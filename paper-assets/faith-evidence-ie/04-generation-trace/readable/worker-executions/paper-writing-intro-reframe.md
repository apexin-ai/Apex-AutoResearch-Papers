# paper writing intro reframe

**Evidence at What Cost? Decoupling and Scaling in LLM-Based Document Relation Extraction** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 21
- **Recorded user turns:** 0
- **Tool calls:** 5
- **Original source:** `logs/workers/worker_paper_writing_intro_reframe_20260520T100725.log`
- **Structured JSON:** [`ffd0adc0cd873b67bdc2.json`](../../sessions/ff/ffd0adc0cd873b67bdc2.json)

## Before a recorded user message

21 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie",
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
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
  "uuid": "b956875e-f2d1-408a-9d42-fc0c8328bce1",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-idea-gen-0513-6-projects-faith-evidence-ie/memory/"
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
    "resetsAt": 1779286200,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "a36f1871-3b99-4247-9ed2-c6501d6f26f0",
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76"
}
```

---

### Assistant

_source line 4_

Let me start by reading the required skill files and the current introduction.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "10beb828-f7a2-45a6-936b-ab79c32ca1a4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012DQntwgKH64Bs9voNo7FhY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14395,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14395
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

_source line 5_

<details open><summary>🔧 Tool call — Read · `toolu_01PxocDnhUtK8ADGMSSRPecS`</summary>

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
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "c8b209c5-f575-447e-ada6-eda2a60de2a6",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012DQntwgKH64Bs9voNo7FhY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14395,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14395
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

_source line 6 · 2026-05-20T10:07:39.638Z_

<details><summary>↩ Tool result · `toolu_01PxocDnhUtK8ADGMSSRPecS`</summary>

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
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "eda17ab7-ee9a-472d-98a0-abb469ba7c58",
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

<details open><summary>🔧 Tool call — Read · `toolu_01VbDr2xjqrBDTESFrVKVkDV`</summary>

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
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "cf147096-de36-4de5-9464-8e5585d85c4a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012DQntwgKH64Bs9voNo7FhY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14395,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14395
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

_source line 8 · 2026-05-20T10:07:40.101Z_

<details><summary>↩ Tool result · `toolu_01VbDr2xjqrBDTESFrVKVkDV`</summary>

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
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "1361997e-9c29-4ae6-92a3-67d1b553bc77",
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

<details open><summary>🔧 Tool call — Read · `toolu_019sJuaPqkAQZoCWbjbwuHBx`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "1686cc18-1183-4863-94de-3810541ed122",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_012DQntwgKH64Bs9voNo7FhY",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 2,
      "cache_creation_input_tokens": 14395,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14395
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

_source line 10 · 2026-05-20T10:07:40.416Z_

<details><summary>↩ Tool result · `toolu_019sJuaPqkAQZoCWbjbwuHBx`</summary>

```text
1	\section{Introduction}
2	
3	Document-level relation extraction (DocRE) requires identifying semantic relations between entity pairs across multiple sentences, a task where encoder-based methods such as \citet{zhou2021atlop} long dominated.
4	Recent LLM-based approaches have closed this gap: \citet{autore2024} fine-tune LLMs with structured decomposition for end-to-end extraction, \citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.
5	These methods approach or surpass encoder baselines on DocRED \citep{yao2019docred} and Re-DocRED \citep{tan2022redocred} in extraction accuracy.
6	Yet every one of them outputs bare relation triplets $(e_h, r, e_t)$ without any indication of \emph{which sentences} in the document support each prediction.
7	In deployment contexts where predictions feed into clinical knowledge bases, legal due-diligence pipelines, or financial compliance systems, end users cannot verify a prediction without manually locating its textual basis across a multi-page document.
8	
9	The absence of verifiable evidence creates a practical bottleneck.
10	Relation extraction outputs are consumed downstream by knowledge graph construction and human decision workflows.
11	When a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.
12	Without machine-generated evidence, this verification requires exhaustive manual review of the input document for every predicted relation.
13	Encoder-based methods have partially addressed this need: \citet{xiao2022sais} introduce sentence-level evidence supervision as an auxiliary signal, and \citet{ma2023dreeam} extend this with dynamic evidence retrieval through memory attention.
14	Both improve extraction quality \emph{and} produce evidence annotations.
15	However, encoder methods now trail LLM-based approaches in extraction accuracy, and their evidence mechanisms (binary sentence classification) do not transfer to generative architectures.
16	The community therefore faces a gap: the most accurate extractors provide no evidence, while the evidence-capable methods are no longer competitive.
17	
18	This gap reflects a deeper structural difference between evidence in encoder and generative frameworks.
19	In SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision.
20	The evidence signal \emph{regularizes} the encoder and improves extraction.
21	In LLM-based DocRE, evidence-grounded extraction requires the model to \emph{generate} complete evidence sentences as part of its output sequence, substantially increasing output length and decoding complexity.
22	Evidence production in this setting is not an auxiliary signal but an additional generation burden that competes with the extraction objective for model capacity.
23	Whether this generation cost necessarily harms extraction, or whether the interaction is more nuanced, remains an open question: the answer may depend on model scale and optimization strategy.
24	This uncertainty motivates a systematic investigation of how evidence production interacts with extraction quality across model scales and optimization paradigms.
25	
26	We formalize evidence-grounded DocRE as a structured generation task for LLMs and conduct a systematic comparison of three post-training optimization paradigms: online reinforcement learning via Group Relative Policy Optimization (GRPO; \citealt{shao2024deepseekmath}), offline preference optimization via Direct Preference Optimization (DPO; \citealt{rafailov2023direct}), and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR; \citealt{zelikman2022star}).
27	Our experiments across 85+ configurations, spanning four model scales (1.7B to 14B), two model families, and two datasets, reveal three principal findings.
28	\textbf{First}, we identify a \emph{decoupling spectrum}: the strength of RL optimization pressure correlates with the severity of evidence-extraction decoupling.
29	GRPO with Quantized Low-Rank Adaptation (QLoRA; \citealt{hu2022lora}) produces catastrophic decoupling where extraction accuracy collapses to near zero; GRPO with full-precision training shows mild decoupling; DPO exhibits gradual degradation; and RSFT maintains stable joint performance.
30	Catastrophic extraction collapse co-occurs with QLoRA-based GRPO training, though we note that GRPO with full-precision training (bf16, $G{=}8$) achieves EDCR below the SFT baseline, indicating that the decoupling is not inherent to online RL when sufficient precision is available.
31	\textbf{Second}, we discover a \emph{scale-dependent evidence tax}: the cost of jointly producing evidence and relations varies across model scales.
32	At 1.7B parameters, evidence generation provides an implicit regularization benefit (tax $-$6.2pp on a controlled evaluation subset); at 4B, the tax reaches +7.5pp; at $\geq$8B, it approaches zero.
33	This pattern challenges the assumption that evidence generation uniformly harms extraction.
34	\textbf{Third}, RSFT with NLI-based scoring for training data selection emerges as the most effective optimization route.
35	By selecting high-quality training samples through output filtering rather than applying gradient-based optimization pressure, RSFT sidesteps the multi-objective competition that destabilizes RL and preference methods.
36	
37	Our contributions are as follows:
38	\begin{enumerate}
39	    \item We formalize \textbf{evidence-grounded document-level relation extraction} as a generation task for LLMs and conduct the first \textbf{comprehensive empirical study} spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms.
40	
41	    \item We characterize a \textbf{decoupling spectrum} across optimization paradigms: RL optimization pressure is associated with evidence-extraction decoupling severity (GRPO catastrophic $\rightarrow$ DPO gradual $\rightarrow$ RSFT none). We use the Evidence-Decoupling Ratio (EDCR), a diagnostic that tracks misalignment between extraction and evidence capabilities, as an analytical tool throughout our study. EDCR shares Rel-Recall with Rel-F1 by construction; we interpret the observed cross-method correlation ($\rho = -0.89$, $n = 7$) as a diagnostic pattern rather than an independent finding, and validate through per-relation analysis ($\rho = -0.79$, $n = 76$) that avoids the shared-component concern.
42	
43	    \item We identify a \textbf{scale-dependent evidence tax}: the cost of joint evidence production varies across 1.7B, 4B, 8B, and 14B parameters, challenging the assumption that evidence generation uniformly degrades extraction quality.
44	
45	    \item We establish \textbf{RSFT with NLI-based scoring} as an effective solution, using CED or flat-NLI to select high-quality training data. RSFT improves mean Ign-F1 at all scales (+1.2 to +6.6pp) with highly reproducible training (variance compression of 7--31$\times$ across scales), and our 1.7B RSFT model (51.19 Ign-F1) approaches 8B SFT performance (50.19), enabling deployment-efficient evidence-grounded extraction at reduced computational cost.
46	\end{enumerate}
47	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "fea35384-83d8-476a-8b62-6c8cb0a7e56c",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
      "content": "\\section{Introduction}\n\nDocument-level relation extraction (DocRE) requires identifying semantic relations between entity pairs across multiple sentences, a task where encoder-based methods such as \\citet{zhou2021atlop} long dominated.\nRecent LLM-based approaches have closed this gap: \\citet{autore2024} fine-tune LLMs with structured decomposition for end-to-end extraction, \\citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \\citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.\nThese methods approach or surpass encoder baselines on DocRED \\citep{yao2019docred} and Re-DocRED \\citep{tan2022redocred} in extraction accuracy.\nYet every one of them outputs bare relation triplets $(e_h, r, e_t)$ without any indication of \\emph{which sentences} in the document support each prediction.\nIn deployment contexts where predictions feed into clinical knowledge bases, legal due-diligence pipelines, or financial compliance systems, end users cannot verify a prediction without manually locating its textual basis across a multi-page document.\n\nThe absence of verifiable evidence creates a practical bottleneck.\nRelation extraction outputs are consumed downstream by knowledge graph construction and human decision workflows.\nWhen a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.\nWithout machine-generated evidence, this verification requires exhaustive manual review of the input document for every predicted relation.\nEncoder-based methods have partially addressed this need: \\citet{xiao2022sais} introduce sentence-level evidence supervision as an auxiliary signal, and \\citet{ma2023dreeam} extend this with dynamic evidence retrieval through memory attention.\nBoth improve extraction quality \\emph{and} produce evidence annotations.\nHowever, encoder methods now trail LLM-based approaches in extraction accuracy, and their evidence mechanisms (binary sentence classification) do not transfer to generative architectures.\nThe community therefore faces a gap: the most accurate extractors provide no evidence, while the evidence-capable methods are no longer competitive.\n\nThis gap reflects a deeper structural difference between evidence in encoder and generative frameworks.\nIn SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision.\nThe evidence signal \\emph{regularizes} the encoder and improves extraction.\nIn LLM-based DocRE, evidence-grounded extraction requires the model to \\emph{generate} complete evidence sentences as part of its output sequence, substantially increasing output length and decoding complexity.\nEvidence production in this setting is not an auxiliary signal but an additional generation burden that competes with the extraction objective for model capacity.\nWhether this generation cost necessarily harms extraction, or whether the interaction is more nuanced, remains an open question: the answer may depend on model scale and optimization strategy.\nThis uncertainty motivates a systematic investigation of how evidence production interacts with extraction quality across model scales and optimization paradigms.\n\nWe formalize evidence-grounded DocRE as a structured generation task for LLMs and conduct a systematic comparison of three post-training optimization paradigms: online reinforcement learning via Group Relative Policy Optimization (GRPO; \\citealt{shao2024deepseekmath}), offline preference optimization via Direct Preference Optimization (DPO; \\citealt{rafailov2023direct}), and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR; \\citealt{zelikman2022star}).\nOur experiments across 85+ configurations, spanning four model scales (1.7B to 14B), two model families, and two datasets, reveal three principal findings.\n\\textbf{First}, we identify a \\emph{decoupling spectrum}: the strength of RL optimization pressure correlates with the severity of evidence-extraction decoupling.\nGRPO with Quantized Low-Rank Adaptation (QLoRA; \\citealt{hu2022lora}) produces catastrophic decoupling where extraction accuracy collapses to near zero; GRPO with full-precision training shows mild decoupling; DPO exhibits gradual degradation; and RSFT maintains stable joint performance.\nCatastrophic extraction collapse co-occurs with QLoRA-based GRPO training, though we note that GRPO with full-precision training (bf16, $G{=}8$) achieves EDCR below the SFT baseline, indicating that the decoupling is not inherent to online RL when sufficient precision is available.\n\\textbf{Second}, we discover a \\emph{scale-dependent evidence tax}: the cost of jointly producing evidence and relations varies across model scales.\nAt 1.7B parameters, evidence generation provides an implicit regularization benefit (tax $-$6.2pp on a controlled evaluation subset); at 4B, the tax reaches +7.5pp; at $\\geq$8B, it approaches zero.\nThis pattern challenges the assumption that evidence generation uniformly harms extraction.\n\\textbf{Third}, RSFT with NLI-based scoring for training data selection emerges as the most effective optimization route.\nBy selecting high-quality training samples through output filtering rather than applying gradient-based optimization pressure, RSFT sidesteps the multi-objective competition that destabilizes RL and preference methods.\n\nOur contributions are as follows:\n\\begin{enumerate}\n    \\item We formalize \\textbf{evidence-grounded document-level relation extraction} as a generation task for LLMs and conduct the first \\textbf{comprehensive empirical study} spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms.\n\n    \\item We characterize a \\textbf{decoupling spectrum} across optimization paradigms: RL optimization pressure is associated with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none). We use the Evidence-Decoupling Ratio (EDCR), a diagnostic that tracks misalignment between extraction and evidence capabilities, as an analytical tool throughout our study. EDCR shares Rel-Recall with Rel-F1 by construction; we interpret the observed cross-method correlation ($\\rho = -0.89$, $n = 7$) as a diagnostic pattern rather than an independent finding, and validate through per-relation analysis ($\\rho = -0.79$, $n = 76$) that avoids the shared-component concern.\n\n    \\item We identify a \\textbf{scale-dependent evidence tax}: the cost of joint evidence production varies across 1.7B, 4B, 8B, and 14B parameters, challenging the assumption that evidence generation uniformly degrades extraction quality.\n\n    \\item We establish \\textbf{RSFT with NLI-based scoring} as an effective solution, using CED or flat-NLI to select high-quality training data. RSFT improves mean Ign-F1 at all scales (+1.2 to +6.6pp) with highly reproducible training (variance compression of 7--31$\\times$ across scales), and our 1.7B RSFT model (51.19 Ign-F1) approaches 8B SFT performance (50.19), enabling deployment-efficient evidence-grounded extraction at reduced computational cost.\n\\end{enumerate}\n",
      "numLines": 47,
      "startLine": 1,
      "totalLines": 47
    }
  }
}
```

</details>

---

### Assistant

_source line 11_

<details><summary>Logged reasoning block</summary>

```text
Now I have a clear picture of:

1. The current introduction content
2. The paper writing norms and LaTeX writing skills
3. The detailed instructions for the rewrite

Let me now write the new introduction following the paragraph structure instructions carefully. Key changes:

1. **¶1**: Preserve core content about DocRE + LLM progress + bare triplets + deployment need
2. **¶2**: Merge the evidence gap paragraphs, compress
3. **¶3**: New "landscape" paragraph - the narrative upgrade core
4. **¶4**: Rewrite findings as "three interacting factors" not "three findings"


5. **¶5**: Three contributions as facets with enumerate

I need to draft each paragraph while adhering to the constraints: no em-dashes, no -ing phrase endings, no overused terms like "delve into" or "leverage", preserve all citations, include the EDCR rho caveat about shared components, and define abbreviations on first use.

Starting with ¶1, I'll compress the problem statement and LLM progress into plain prose that sets up why DocRE matters and why current methods fall short.

For ¶2, the evidence gap is the crux: the most accurate models don't produce evidence, while evidence-capable models sacrifice accuracy. I need to show this as a genuine bottleneck without restating what's already covered.

For ¶3, the key insight is that evidence's role isn't inherent to the task—it shifts based on model capacity, optimization approach, and data quality. Small models benefit from evidence as regularization, mid-sized ones face tradeoffs, and large models absorb it. Gradient-based training creates destructive conflicts between accuracy and evidence, whereas discrete selection methods avoid this. High-quality training data transforms evidence from a burden into a learning scaffold. This reframes the entire landscape.

Now I'm drafting the introduction section. I need to establish DocRE, note that encoders dominated, then pivot to the evidence problem. The opening should be clean and direct—no em-dashes, no -ing forms. I'll keep citations intact, define abbreviations, and include the EDCR caveat where it belongs. Three contributions follow: formalizing evidence-grounded extraction, revealing the three governing factors, and the practical framework. The absence of verifiable evidence creates a practical bottleneck in deployment contexts. When systems predict drug-gene interactions or contract liabilities, practitioners need to trace predictions back to source text before acting on them. Encoder-based methods have partially addressed this through sentence-level evidence supervision and dynamic retrieval mechanisms, producing evidence annotations that improve extraction quality, but they've fallen behind LLM-based approaches in accuracy. So we're stuck with a tradeoff: the most accurate extractors provide no evidence, while methods that do generate evidence are no longer competitive.

This gap stems from fundamental architectural differences in how evidence operates at different scales. For encoders, evidence retrieval is a straightforward binary classification task that acts as auxiliary supervision, regularizing the model with minimal overhead. For LLMs doing document-level relation extraction, generating evidence means producing complete sentences as part of the output sequence, which substantially increases decoding complexity. But whether this cost is actually prohibitive depends on several factors: model capacity, where smaller models benefit from the regularization while mid-scale models face capacity competition and larger ones absorb the overhead; the optimization approach, where gradient-based training creates destructive tradeoffs between evidence and extraction objectives while discrete sampling avoids them; and data quality, where filtering with natural language inference can flip evidence from a burden into a learning scaffold. So understanding these dynamics is essential for building evidence-grounded extraction systems that work well in practice.

Now I'm formalizing evidence-grounded document relation extraction as a structured generation task and comparing three different post-training optimization approaches: online reinforcement learning through Group Relative Policy Optimization, offline preference optimization through Direct Preference Optimization, and offline reinforcement learning through Rejection Sampling Fine-Tuning.

Across 85+ experimental configurations spanning four model sizes from 1.7B to 14B parameters, two model families, and two datasets, I'm finding that evidence generation's impact depends on three key factors. The evidence cost varies non-monotonically with model capacity—it provides regularization benefits at smaller scales, becomes a significant penalty at 4B parameters, and essentially disappears at 8B and beyond. Across the different optimization paradigms, there's a clear spectrum where stronger RL pressure correlates with worse evidence-extraction decoupling, ranging from catastrophic failures with GRPO to gradual degradation with DPO to no decoupling with RSFT.

The catastrophic collapse I'm seeing with GRPO appears tied to quantization during training, but when using full precision, GRPO actually stays below the supervised baseline, suggesting the decoupling isn't inherent to online RL itself when precision is sufficient. Meanwhile, RSFT with quality-based filtering sidesteps this problem entirely by selecting high-quality examples rather than applying gradient pressure, consistently improving performance across all scales while dramatically reducing training variance.

Now I'm checking which abbreviations need defining in the introduction—LLM appears early without definition, so I should expand it on first mention. Let me revise that section to properly introduce Large Language Models where it first appears.

For the contributions section, I need to follow the exact structure provided in the instructions: three distinct facets covering the evidence generation landscape, the decoupling spectrum, and the RSFT approach with NLI-based scoring. I'll make sure to include all the required method citations like GRPO, DPO, and LoRA where appropriate. I'm checking whether the cross-method correlation (ρ=−0.89) needs to be mentioned in the paragraph 4 body text, which would require the caveat about EDCR sharing components with Rel-Recall and Rel-F1. Since my draft doesn't reference that correlation and the provided contribution text focuses only on the per-relation validation, I'll stick with what's already specified.

I also need to make sure EDCR gets defined when it's first introduced in the diagnostic metric discussion, rather than assuming readers know it stands for Evidence-Decoupling Ratio from the contributions section. I'm deciding whether to include the cross-method correlation details in the body text of paragraph 4 or keep them confined to the contribution section. Since the instructions focus the paradigm dimension on the decoupling spectrum pattern itself, I'll stick with the qualitative findings in the body text and reserve the quantitative EDCR validation for the contribution list where it belongs.

Now I need to weave in those specific performance numbers for the data quality dimension—the improvement range across scales and the variance compression—along with the comparison showing how the 1.7B RSFT model approaches larger SFT performance while being more predictable. I'll draft the full introduction carefully, making sure to define abbreviations on first mention, preserve all citations, include the correlation caveat where needed, and avoid em-dashes and -ing constructions. I need to verify the EDCR acronym is properly defined with its full name, then draft the introduction section carefully, making sure the formatting and punctuation are consistent throughout—particularly watching for proper em-dash usage and mathematical notation. The gap between accurate extractors and evidence-capable methods stems from fundamental architectural differences: encoder methods treat evidence as auxiliary binary classification that regularizes learning, while LLMs must generate full evidence sentences, increasing output length and decoding cost. This trade-off isn't uniform—it depends on model capacity (where smaller models benefit from the regularization but mid-scale ones suffer from competing objectives), optimization approach (gradient-based methods create destructive trade-offs while discrete selection avoids them), and training data quality (where filtering can shift evidence from a liability to an asset).

I'm formalizing evidence-grounded DocRE as structured generation and comparing three post-training approaches across 85+ configurations spanning four model scales and two datasets. The results show evidence generation's role varies non-monotonically with capacity—providing regularization benefits at 1.7B, imposing substantial costs at 4B, and approaching neutral at 8B+—while the optimization paradigm creates a decoupling spectrum from catastrophic collapse in online RL to graceful degradation in preference optimization to no conflict in rejection sampling. Using NLI-based filtering to select high-quality samples sidesteps these trade-offs entirely, improving performance across all scales while dramatically reducing training variance. a scale-dependent evidence tax that varies from beneficial at smaller scales to costly at larger ones, challenging the assumption that evidence generation uniformly harms extraction. I'm also characterizing a decoupling spectrum that explains why gradient-based methods fail at joint generation—the optimization pressure correlates with how severely evidence and extraction decouple, ranging from catastrophic in GRPO to gradual in DPO to nonexistent in RSFT. I've introduced the Evidence-Decoupling Ratio as a diagnostic metric with strong validation across relations. RSFT with NLI-based scoring emerges as the effective strategy here, consistently improving performance across all scales while dramatically reducing variance, and the smaller 1.7B model achieves comparable results to much larger baselines while being far more stable and practical for deployment. I'm verifying that all the citations are preserved correctly and checking whether I need to include the correlation coefficient for EDCR in the contribution section based on the specific instructions provided. I need to define NLI since it first appears in paragraph 3. Let me add "Natural Language Inference (NLI)" when I introduce the NLI-based filtering approach, so it reads something like "filtering based on Natural Language Inference (NLI) scores" in that section.

Now I'm checking whether other terms like Ign-F1, SAIS, and DREEAM need definitions too. Ign-F1 is a standard metric in DocRE work, so that should be fine without definition. SAIS and DREEAM are method names from other papers, so they probably don't need defining either—they're just being referenced as prior work. I'm validating the EDCR metric against the per-relation analysis results to confirm statistical significance, then moving on to finalize the contribution statements.

Now I need to convert the mathematical notation to proper LaTeX formatting—replacing symbols like arrows, Greek letters, and operators with their LaTeX equivalents—and then replace the entire section from the Introduction heading onward while preserving that section marker itself.

I'm also noticing that the third contribution ends with a participial phrase starting with "enabling," which violates the constraint about not ending with -ing words, so I should restructure that to end with a period instead. I'm working through how to rephrase this to avoid the -ing ending while keeping the meaning intact. Breaking it into two sentences feels cleaner—I can say the model is smaller and more predictable, then follow with a separate statement about what that enables. Let me also scan the other contributions for similar -ing patterns that violate the style guidelines and fix those too. I've confirmed the paragraph lengths are all within normal range, and the three contributions align with the requirement for three facets. Now I need to verify the LoRA citation is correctly referenced before finalizing the draft. I'm verifying the en-dash formatting is correct in the variance compression claim, then doing a final read-through to ensure the narrative flows smoothly from the evidence problem through the three interacting factors to RSFT as the solution. I'm also confirming the required citations in paragraphs 2 and 3 are preserved as instructed. I'm verifying the ¶4 body should include the improvement range and variance compression metrics, but save the specific 1.7B versus 8B model comparison for contribution 3, which aligns with my current draft. Let me do a final check against the writing guidelines—no em-dashes, no -ing phrase endings, avoiding clichéd terms—then proceed with the edit. I'm verifying that none of my sentences end with participial phrases like "highlighting" or "demonstrating"—most look good, though I want to make sure constructions like "before acting on it" count as standard prepositional phrases rather than the trailing -ing pattern the guidelines are targeting. I've verified all the sentence fragments and checked for repetitive transition words—everything looks solid. Now I'm deciding whether to define "Ign-F1" in the introduction, but since it's a standard metric in document relation extraction papers and will be properly defined in the experiments section anyway, I'll leave it as is and finalize the edits. I've decided to leave Ign-F1 undefined since it's not flagged as an issue and the current intro follows that convention. Now I'm preparing the edit by constructing the old and new strings—I need to replace everything from `\section{Introduction}` through the end of the file, keeping that section header intact.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "dbe672ef-8fc9-4217-b90d-da512f32b0a4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019YvHyEVg6w5hf9Jgu4ggxV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13052,
      "cache_read_input_tokens": 26236,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13052
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

_source line 12_

Now I'll write the rewritten introduction. Let me compose it carefully following all constraints.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "98cbee19-2f52-4bc2-90f7-f0669db483e4",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019YvHyEVg6w5hf9Jgu4ggxV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13052,
      "cache_read_input_tokens": 26236,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13052
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

_source line 13_

<details open><summary>🔧 Tool call — Edit · `toolu_015kTT5ybuAd7muXijiCoezn`</summary>

```json
{
  "replace_all": false,
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
  "old_string": "\\section{Introduction}\n\nDocument-level relation extraction (DocRE) requires identifying semantic relations between entity pairs across multiple sentences, a task where encoder-based methods such as \\citet{zhou2021atlop} long dominated.\nRecent LLM-based approaches have closed this gap: \\citet{autore2024} fine-tune LLMs with structured decomposition for end-to-end extraction, \\citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \\citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.\nThese methods approach or surpass encoder baselines on DocRED \\citep{yao2019docred} and Re-DocRED \\citep{tan2022redocred} in extraction accuracy.\nYet every one of them outputs bare relation triplets $(e_h, r, e_t)$ without any indication of \\emph{which sentences} in the document support each prediction.\nIn deployment contexts where predictions feed into clinical knowledge bases, legal due-diligence pipelines, or financial compliance systems, end users cannot verify a prediction without manually locating its textual basis across a multi-page document.\n\nThe absence of verifiable evidence creates a practical bottleneck.\nRelation extraction outputs are consumed downstream by knowledge graph construction and human decision workflows.\nWhen a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.\nWithout machine-generated evidence, this verification requires exhaustive manual review of the input document for every predicted relation.\nEncoder-based methods have partially addressed this need: \\citet{xiao2022sais} introduce sentence-level evidence supervision as an auxiliary signal, and \\citet{ma2023dreeam} extend this with dynamic evidence retrieval through memory attention.\nBoth improve extraction quality \\emph{and} produce evidence annotations.\nHowever, encoder methods now trail LLM-based approaches in extraction accuracy, and their evidence mechanisms (binary sentence classification) do not transfer to generative architectures.\nThe community therefore faces a gap: the most accurate extractors provide no evidence, while the evidence-capable methods are no longer competitive.\n\nThis gap reflects a deeper structural difference between evidence in encoder and generative frameworks.\nIn SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision.\nThe evidence signal \\emph{regularizes} the encoder and improves extraction.\nIn LLM-based DocRE, evidence-grounded extraction requires the model to \\emph{generate} complete evidence sentences as part of its output sequence, substantially increasing output length and decoding complexity.\nEvidence production in this setting is not an auxiliary signal but an additional generation burden that competes with the extraction objective for model capacity.\nWhether this generation cost necessarily harms extraction, or whether the interaction is more nuanced, remains an open question: the answer may depend on model scale and optimization strategy.\nThis uncertainty motivates a systematic investigation of how evidence production interacts with extraction quality across model scales and optimization paradigms.\n\nWe formalize evidence-grounded DocRE as a structured generation task for LLMs and conduct a systematic comparison of three post-training optimization paradigms: online reinforcement learning via Group Relative Policy Optimization (GRPO; \\citealt{shao2024deepseekmath}), offline preference optimization via Direct Preference Optimization (DPO; \\citealt{rafailov2023direct}), and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR; \\citealt{zelikman2022star}).\nOur experiments across 85+ configurations, spanning four model scales (1.7B to 14B), two model families, and two datasets, reveal three principal findings.\n\\textbf{First}, we identify a \\emph{decoupling spectrum}: the strength of RL optimization pressure correlates with the severity of evidence-extraction decoupling.\nGRPO with Quantized Low-Rank Adaptation (QLoRA; \\citealt{hu2022lora}) produces catastrophic decoupling where extraction accuracy collapses to near zero; GRPO with full-precision training shows mild decoupling; DPO exhibits gradual degradation; and RSFT maintains stable joint performance.\nCatastrophic extraction collapse co-occurs with QLoRA-based GRPO training, though we note that GRPO with full-precision training (bf16, $G{=}8$) achieves EDCR below the SFT baseline, indicating that the decoupling is not inherent to online RL when sufficient precision is available.\n\\textbf{Second}, we discover a \\emph{scale-dependent evidence tax}: the cost of jointly producing evidence and relations varies across model scales.\nAt 1.7B parameters, evidence generation provides an implicit regularization benefit (tax $-$6.2pp on a controlled evaluation subset); at 4B, the tax reaches +7.5pp; at $\\geq$8B, it approaches zero.\nThis pattern challenges the assumption that evidence generation uniformly harms extraction.\n\\textbf{Third}, RSFT with NLI-based scoring for training data selection emerges as the most effective optimization route.\nBy selecting high-quality training samples through output filtering rather than applying gradient-based optimization pressure, RSFT sidesteps the multi-objective competition that destabilizes RL and preference methods.\n\nOur contributions are as follows:\n\\begin{enumerate}\n    \\item We formalize \\textbf{evidence-grounded document-level relation extraction} as a generation task for LLMs and conduct the first \\textbf{comprehensive empirical study} spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms.\n\n    \\item We characterize a \\textbf{decoupling spectrum} across optimization paradigms: RL optimization pressure is associated with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none). We use the Evidence-Decoupling Ratio (EDCR), a diagnostic that tracks misalignment between extraction and evidence capabilities, as an analytical tool throughout our study. EDCR shares Rel-Recall with Rel-F1 by construction; we interpret the observed cross-method correlation ($\\rho = -0.89$, $n = 7$) as a diagnostic pattern rather than an independent finding, and validate through per-relation analysis ($\\rho = -0.79$, $n = 76$) that avoids the shared-component concern.\n\n    \\item We identify a \\textbf{scale-dependent evidence tax}: the cost of joint evidence production varies across 1.7B, 4B, 8B, and 14B parameters, challenging the assumption that evidence generation uniformly degrades extraction quality.\n\n    \\item We establish \\textbf{RSFT with NLI-based scoring} as an effective solution, using CED or flat-NLI to select high-quality training data. RSFT improves mean Ign-F1 at all scales (+1.2 to +6.6pp) with highly reproducible training (variance compression of 7--31$\\times$ across scales), and our 1.7B RSFT model (51.19 Ign-F1) approaches 8B SFT performance (50.19), enabling deployment-efficient evidence-grounded extraction at reduced computational cost.\n\\end{enumerate}",
  "new_string": "\\section{Introduction}\n\nDocument-level relation extraction (DocRE) requires identifying semantic relations between entity pairs across multiple sentences, a task where encoder-based methods such as \\citet{zhou2021atlop} long dominated.\nRecent approaches based on Large Language Models (LLMs) have closed this gap: \\citet{autore2024} fine-tune LLMs with structured decomposition for end-to-end extraction, \\citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \\citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.\nThese methods approach or surpass encoder baselines on DocRED \\citep{yao2019docred} and Re-DocRED \\citep{tan2022redocred} in extraction accuracy.\nYet every one of them outputs bare relation triplets $(e_h, r, e_t)$ without any indication of \\emph{which sentences} in the document support each prediction.\nIn deployment contexts where predictions feed into clinical knowledge bases, legal due-diligence pipelines, or financial compliance systems, end users cannot verify a prediction without manually locating its textual basis across a multi-page document.\n\nThe absence of verifiable evidence creates a practical bottleneck.\nRelation extraction outputs feed downstream knowledge graph construction and human decision workflows; when a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.\nEncoder-based methods have partially addressed this need: \\citet{xiao2022sais} introduce sentence-level evidence supervision as an auxiliary signal, and \\citet{ma2023dreeam} extend this with dynamic evidence retrieval through memory attention.\nBoth produce evidence annotations and improve extraction quality, but encoder methods now trail LLM-based approaches in extraction accuracy.\nThe community therefore faces a gap: the most accurate extractors provide no evidence, while the evidence-capable methods are no longer competitive.\n\nThis gap reflects a deeper structural difference in how evidence functions across architectures and scales.\nIn encoder-based methods such as SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision; the evidence signal regularizes the encoder and improves extraction at minimal cost.\nIn LLM-based DocRE, evidence-grounded extraction requires the model to \\emph{generate} complete evidence sentences as part of its output sequence, substantially increasing output length and decoding complexity.\nYet the role of this generation cost is not fixed.\nIt depends on at least three factors: \\emph{model capacity}, where small models benefit from the implicit regularization that evidence provides while mid-scale models suffer from capacity competition and larger models absorb the overhead; \\emph{optimization paradigm}, where gradient-based methods create destructive trade-offs between evidence and extraction objectives while discrete sample selection avoids them entirely; and \\emph{training data quality}, where filtering based on Natural Language Inference (NLI) scores can transform evidence from an optimization burden into a learning scaffold.\nUnderstanding this landscape is a prerequisite for deploying evidence-grounded extraction systems that are both accurate and verifiable.\n\nWe formalize evidence-grounded DocRE as a structured generation task and conduct a systematic comparison of three post-training paradigms: online reinforcement learning via Group Relative Policy Optimization (GRPO; \\citealt{shao2024deepseekmath}), offline preference optimization via Direct Preference Optimization (DPO; \\citealt{rafailov2023direct}), and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR; \\citealt{zelikman2022star}).\nOur experiments across 85+ configurations, spanning four model scales (1.7B to 14B), two model families, and two datasets, reveal that the role of evidence generation is governed by three interacting factors.\nAlong the \\emph{capacity dimension}, the evidence tax varies non-monotonically: evidence generation provides implicit regularization at 1.7B ($-$6.2pp Ign-F1), imposes a substantial cost at 4B (+7.5pp), and approaches zero at $\\geq$8B parameters.\nAlong the \\emph{paradigm dimension}, we observe a decoupling spectrum in which the strength of optimization pressure correlates with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none); catastrophic extraction collapse co-occurs with Quantized Low-Rank Adaptation (QLoRA; \\citealt{hu2022lora}) in GRPO, though full-precision GRPO achieves decoupling below the supervised fine-tuning (SFT) baseline, which indicates that the collapse is not inherent to online RL when sufficient precision is available.\nAlong the \\emph{data quality dimension}, RSFT with NLI-based scoring navigates this landscape by selecting high-quality training samples through output filtering rather than applying gradient-based pressure; it improves mean Ign-F1 at all scales (+1.2 to +6.6pp) while compressing training variance 7--31$\\times$.\n\nOur contributions are as follows:\n\\begin{enumerate}\n    \\item We map the \\textbf{evidence generation landscape} through a comprehensive empirical study spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms. We identify a \\textbf{scale-dependent evidence tax} that varies from beneficial ($-$6.2pp at 1.7B) to costly (+7.5pp at 4B) to negligible ($\\geq$8B). This pattern challenges the assumption that evidence generation uniformly harms extraction.\n\n    \\item We characterize a \\textbf{decoupling spectrum} that explains why gradient-based paradigms fail at joint evidence-and-extraction generation: RL optimization pressure correlates with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none). We introduce the Evidence-Decoupling Ratio (EDCR) as a diagnostic metric, validated through per-relation analysis ($\\rho = -0.79$, $n = 76$, $p < 0.0001$).\n\n    \\item We establish \\textbf{RSFT with NLI-based scoring} as an effective navigation strategy for this landscape. RSFT improves mean Ign-F1 at all scales (+1.2 to +6.6pp) with 7--31$\\times$ variance compression, and our 1.7B RSFT model (51.19 Ign-F1, std 0.09pp) approaches 8B SFT performance (50.19, std 3.72pp) while being 4.7$\\times$ smaller and substantially more predictable. This combination enables deployment-efficient evidence-grounded extraction.\n\\end{enumerate}"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "52f80af2-0667-4305-9756-91c139bd41c5",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_019YvHyEVg6w5hf9Jgu4ggxV",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 13052,
      "cache_read_input_tokens": 26236,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 13052
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

_source line 14 · 2026-05-20T10:11:23.818Z_

<details><summary>↩ Tool result · `toolu_015kTT5ybuAd7muXijiCoezn`</summary>

```text
The file /home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "d8c5c060-9c3b-4439-bb3b-96694deca872",
  "tool_use_result": {
    "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
    "oldString": "\\section{Introduction}\n\nDocument-level relation extraction (DocRE) requires identifying semantic relations between entity pairs across multiple sentences, a task where encoder-based methods such as \\citet{zhou2021atlop} long dominated.\nRecent LLM-based approaches have closed this gap: \\citet{autore2024} fine-tune LLMs with structured decomposition for end-to-end extraction, \\citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \\citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.\nThese methods approach or surpass encoder baselines on DocRED \\citep{yao2019docred} and Re-DocRED \\citep{tan2022redocred} in extraction accuracy.\nYet every one of them outputs bare relation triplets $(e_h, r, e_t)$ without any indication of \\emph{which sentences} in the document support each prediction.\nIn deployment contexts where predictions feed into clinical knowledge bases, legal due-diligence pipelines, or financial compliance systems, end users cannot verify a prediction without manually locating its textual basis across a multi-page document.\n\nThe absence of verifiable evidence creates a practical bottleneck.\nRelation extraction outputs are consumed downstream by knowledge graph construction and human decision workflows.\nWhen a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.\nWithout machine-generated evidence, this verification requires exhaustive manual review of the input document for every predicted relation.\nEncoder-based methods have partially addressed this need: \\citet{xiao2022sais} introduce sentence-level evidence supervision as an auxiliary signal, and \\citet{ma2023dreeam} extend this with dynamic evidence retrieval through memory attention.\nBoth improve extraction quality \\emph{and} produce evidence annotations.\nHowever, encoder methods now trail LLM-based approaches in extraction accuracy, and their evidence mechanisms (binary sentence classification) do not transfer to generative architectures.\nThe community therefore faces a gap: the most accurate extractors provide no evidence, while the evidence-capable methods are no longer competitive.\n\nThis gap reflects a deeper structural difference between evidence in encoder and generative frameworks.\nIn SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision.\nThe evidence signal \\emph{regularizes} the encoder and improves extraction.\nIn LLM-based DocRE, evidence-grounded extraction requires the model to \\emph{generate} complete evidence sentences as part of its output sequence, substantially increasing output length and decoding complexity.\nEvidence production in this setting is not an auxiliary signal but an additional generation burden that competes with the extraction objective for model capacity.\nWhether this generation cost necessarily harms extraction, or whether the interaction is more nuanced, remains an open question: the answer may depend on model scale and optimization strategy.\nThis uncertainty motivates a systematic investigation of how evidence production interacts with extraction quality across model scales and optimization paradigms.\n\nWe formalize evidence-grounded DocRE as a structured generation task for LLMs and conduct a systematic comparison of three post-training optimization paradigms: online reinforcement learning via Group Relative Policy Optimization (GRPO; \\citealt{shao2024deepseekmath}), offline preference optimization via Direct Preference Optimization (DPO; \\citealt{rafailov2023direct}), and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR; \\citealt{zelikman2022star}).\nOur experiments across 85+ configurations, spanning four model scales (1.7B to 14B), two model families, and two datasets, reveal three principal findings.\n\\textbf{First}, we identify a \\emph{decoupling spectrum}: the strength of RL optimization pressure correlates with the severity of evidence-extraction decoupling.\nGRPO with Quantized Low-Rank Adaptation (QLoRA; \\citealt{hu2022lora}) produces catastrophic decoupling where extraction accuracy collapses to near zero; GRPO with full-precision training shows mild decoupling; DPO exhibits gradual degradation; and RSFT maintains stable joint performance.\nCatastrophic extraction collapse co-occurs with QLoRA-based GRPO training, though we note that GRPO with full-precision training (bf16, $G{=}8$) achieves EDCR below the SFT baseline, indicating that the decoupling is not inherent to online RL when sufficient precision is available.\n\\textbf{Second}, we discover a \\emph{scale-dependent evidence tax}: the cost of jointly producing evidence and relations varies across model scales.\nAt 1.7B parameters, evidence generation provides an implicit regularization benefit (tax $-$6.2pp on a controlled evaluation subset); at 4B, the tax reaches +7.5pp; at $\\geq$8B, it approaches zero.\nThis pattern challenges the assumption that evidence generation uniformly harms extraction.\n\\textbf{Third}, RSFT with NLI-based scoring for training data selection emerges as the most effective optimization route.\nBy selecting high-quality training samples through output filtering rather than applying gradient-based optimization pressure, RSFT sidesteps the multi-objective competition that destabilizes RL and preference methods.\n\nOur contributions are as follows:\n\\begin{enumerate}\n    \\item We formalize \\textbf{evidence-grounded document-level relation extraction} as a generation task for LLMs and conduct the first \\textbf{comprehensive empirical study} spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms.\n\n    \\item We characterize a \\textbf{decoupling spectrum} across optimization paradigms: RL optimization pressure is associated with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none). We use the Evidence-Decoupling Ratio (EDCR), a diagnostic that tracks misalignment between extraction and evidence capabilities, as an analytical tool throughout our study. EDCR shares Rel-Recall with Rel-F1 by construction; we interpret the observed cross-method correlation ($\\rho = -0.89$, $n = 7$) as a diagnostic pattern rather than an independent finding, and validate through per-relation analysis ($\\rho = -0.79$, $n = 76$) that avoids the shared-component concern.\n\n    \\item We identify a \\textbf{scale-dependent evidence tax}: the cost of joint evidence production varies across 1.7B, 4B, 8B, and 14B parameters, challenging the assumption that evidence generation uniformly degrades extraction quality.\n\n    \\item We establish \\textbf{RSFT with NLI-based scoring} as an effective solution, using CED or flat-NLI to select high-quality training data. RSFT improves mean Ign-F1 at all scales (+1.2 to +6.6pp) with highly reproducible training (variance compression of 7--31$\\times$ across scales), and our 1.7B RSFT model (51.19 Ign-F1) approaches 8B SFT performance (50.19), enabling deployment-efficient evidence-grounded extraction at reduced computational cost.\n\\end{enumerate}",
    "newString": "\\section{Introduction}\n\nDocument-level relation extraction (DocRE) requires identifying semantic relations between entity pairs across multiple sentences, a task where encoder-based methods such as \\citet{zhou2021atlop} long dominated.\nRecent approaches based on Large Language Models (LLMs) have closed this gap: \\citet{autore2024} fine-tune LLMs with structured decomposition for end-to-end extraction, \\citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \\citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.\nThese methods approach or surpass encoder baselines on DocRED \\citep{yao2019docred} and Re-DocRED \\citep{tan2022redocred} in extraction accuracy.\nYet every one of them outputs bare relation triplets $(e_h, r, e_t)$ without any indication of \\emph{which sentences} in the document support each prediction.\nIn deployment contexts where predictions feed into clinical knowledge bases, legal due-diligence pipelines, or financial compliance systems, end users cannot verify a prediction without manually locating its textual basis across a multi-page document.\n\nThe absence of verifiable evidence creates a practical bottleneck.\nRelation extraction outputs feed downstream knowledge graph construction and human decision workflows; when a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.\nEncoder-based methods have partially addressed this need: \\citet{xiao2022sais} introduce sentence-level evidence supervision as an auxiliary signal, and \\citet{ma2023dreeam} extend this with dynamic evidence retrieval through memory attention.\nBoth produce evidence annotations and improve extraction quality, but encoder methods now trail LLM-based approaches in extraction accuracy.\nThe community therefore faces a gap: the most accurate extractors provide no evidence, while the evidence-capable methods are no longer competitive.\n\nThis gap reflects a deeper structural difference in how evidence functions across architectures and scales.\nIn encoder-based methods such as SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision; the evidence signal regularizes the encoder and improves extraction at minimal cost.\nIn LLM-based DocRE, evidence-grounded extraction requires the model to \\emph{generate} complete evidence sentences as part of its output sequence, substantially increasing output length and decoding complexity.\nYet the role of this generation cost is not fixed.\nIt depends on at least three factors: \\emph{model capacity}, where small models benefit from the implicit regularization that evidence provides while mid-scale models suffer from capacity competition and larger models absorb the overhead; \\emph{optimization paradigm}, where gradient-based methods create destructive trade-offs between evidence and extraction objectives while discrete sample selection avoids them entirely; and \\emph{training data quality}, where filtering based on Natural Language Inference (NLI) scores can transform evidence from an optimization burden into a learning scaffold.\nUnderstanding this landscape is a prerequisite for deploying evidence-grounded extraction systems that are both accurate and verifiable.\n\nWe formalize evidence-grounded DocRE as a structured generation task and conduct a systematic comparison of three post-training paradigms: online reinforcement learning via Group Relative Policy Optimization (GRPO; \\citealt{shao2024deepseekmath}), offline preference optimization via Direct Preference Optimization (DPO; \\citealt{rafailov2023direct}), and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR; \\citealt{zelikman2022star}).\nOur experiments across 85+ configurations, spanning four model scales (1.7B to 14B), two model families, and two datasets, reveal that the role of evidence generation is governed by three interacting factors.\nAlong the \\emph{capacity dimension}, the evidence tax varies non-monotonically: evidence generation provides implicit regularization at 1.7B ($-$6.2pp Ign-F1), imposes a substantial cost at 4B (+7.5pp), and approaches zero at $\\geq$8B parameters.\nAlong the \\emph{paradigm dimension}, we observe a decoupling spectrum in which the strength of optimization pressure correlates with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none); catastrophic extraction collapse co-occurs with Quantized Low-Rank Adaptation (QLoRA; \\citealt{hu2022lora}) in GRPO, though full-precision GRPO achieves decoupling below the supervised fine-tuning (SFT) baseline, which indicates that the collapse is not inherent to online RL when sufficient precision is available.\nAlong the \\emph{data quality dimension}, RSFT with NLI-based scoring navigates this landscape by selecting high-quality training samples through output filtering rather than applying gradient-based pressure; it improves mean Ign-F1 at all scales (+1.2 to +6.6pp) while compressing training variance 7--31$\\times$.\n\nOur contributions are as follows:\n\\begin{enumerate}\n    \\item We map the \\textbf{evidence generation landscape} through a comprehensive empirical study spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms. We identify a \\textbf{scale-dependent evidence tax} that varies from beneficial ($-$6.2pp at 1.7B) to costly (+7.5pp at 4B) to negligible ($\\geq$8B). This pattern challenges the assumption that evidence generation uniformly harms extraction.\n\n    \\item We characterize a \\textbf{decoupling spectrum} that explains why gradient-based paradigms fail at joint evidence-and-extraction generation: RL optimization pressure correlates with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none). We introduce the Evidence-Decoupling Ratio (EDCR) as a diagnostic metric, validated through per-relation analysis ($\\rho = -0.79$, $n = 76$, $p < 0.0001$).\n\n    \\item We establish \\textbf{RSFT with NLI-based scoring} as an effective navigation strategy for this landscape. RSFT improves mean Ign-F1 at all scales (+1.2 to +6.6pp) with 7--31$\\times$ variance compression, and our 1.7B RSFT model (51.19 Ign-F1, std 0.09pp) approaches 8B SFT performance (50.19, std 3.72pp) while being 4.7$\\times$ smaller and substantially more predictable. This combination enables deployment-efficient evidence-grounded extraction.\n\\end{enumerate}",
    "originalFile": "\\section{Introduction}\n\nDocument-level relation extraction (DocRE) requires identifying semantic relations between entity pairs across multiple sentences, a task where encoder-based methods such as \\citet{zhou2021atlop} long dominated.\nRecent LLM-based approaches have closed this gap: \\citet{autore2024} fine-tune LLMs with structured decomposition for end-to-end extraction, \\citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \\citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.\nThese methods approach or surpass encoder baselines on DocRED \\citep{yao2019docred} and Re-DocRED \\citep{tan2022redocred} in extraction accuracy.\nYet every one of them outputs bare relation triplets $(e_h, r, e_t)$ without any indication of \\emph{which sentences} in the document support each prediction.\nIn deployment contexts where predictions feed into clinical knowledge bases, legal due-diligence pipelines, or financial compliance systems, end users cannot verify a prediction without manually locating its textual basis across a multi-page document.\n\nThe absence of verifiable evidence creates a practical bottleneck.\nRelation extraction outputs are consumed downstream by knowledge graph construction and human decision workflows.\nWhen a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.\nWithout machine-generated evidence, this verification requires exhaustive manual review of the input document for every predicted relation.\nEncoder-based methods have partially addressed this need: \\citet{xiao2022sais} introduce sentence-level evidence supervision as an auxiliary signal, and \\citet{ma2023dreeam} extend this with dynamic evidence retrieval through memory attention.\nBoth improve extraction quality \\emph{and} produce evidence annotations.\nHowever, encoder methods now trail LLM-based approaches in extraction accuracy, and their evidence mechanisms (binary sentence classification) do not transfer to generative architectures.\nThe community therefore faces a gap: the most accurate extractors provide no evidence, while the evidence-capable methods are no longer competitive.\n\nThis gap reflects a deeper structural difference between evidence in encoder and generative frameworks.\nIn SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision.\nThe evidence signal \\emph{regularizes} the encoder and improves extraction.\nIn LLM-based DocRE, evidence-grounded extraction requires the model to \\emph{generate} complete evidence sentences as part of its output sequence, substantially increasing output length and decoding complexity.\nEvidence production in this setting is not an auxiliary signal but an additional generation burden that competes with the extraction objective for model capacity.\nWhether this generation cost necessarily harms extraction, or whether the interaction is more nuanced, remains an open question: the answer may depend on model scale and optimization strategy.\nThis uncertainty motivates a systematic investigation of how evidence production interacts with extraction quality across model scales and optimization paradigms.\n\nWe formalize evidence-grounded DocRE as a structured generation task for LLMs and conduct a systematic comparison of three post-training optimization paradigms: online reinforcement learning via Group Relative Policy Optimization (GRPO; \\citealt{shao2024deepseekmath}), offline preference optimization via Direct Preference Optimization (DPO; \\citealt{rafailov2023direct}), and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR; \\citealt{zelikman2022star}).\nOur experiments across 85+ configurations, spanning four model scales (1.7B to 14B), two model families, and two datasets, reveal three principal findings.\n\\textbf{First}, we identify a \\emph{decoupling spectrum}: the strength of RL optimization pressure correlates with the severity of evidence-extraction decoupling.\nGRPO with Quantized Low-Rank Adaptation (QLoRA; \\citealt{hu2022lora}) produces catastrophic decoupling where extraction accuracy collapses to near zero; GRPO with full-precision training shows mild decoupling; DPO exhibits gradual degradation; and RSFT maintains stable joint performance.\nCatastrophic extraction collapse co-occurs with QLoRA-based GRPO training, though we note that GRPO with full-precision training (bf16, $G{=}8$) achieves EDCR below the SFT baseline, indicating that the decoupling is not inherent to online RL when sufficient precision is available.\n\\textbf{Second}, we discover a \\emph{scale-dependent evidence tax}: the cost of jointly producing evidence and relations varies across model scales.\nAt 1.7B parameters, evidence generation provides an implicit regularization benefit (tax $-$6.2pp on a controlled evaluation subset); at 4B, the tax reaches +7.5pp; at $\\geq$8B, it approaches zero.\nThis pattern challenges the assumption that evidence generation uniformly harms extraction.\n\\textbf{Third}, RSFT with NLI-based scoring for training data selection emerges as the most effective optimization route.\nBy selecting high-quality training samples through output filtering rather than applying gradient-based optimization pressure, RSFT sidesteps the multi-objective competition that destabilizes RL and preference methods.\n\nOur contributions are as follows:\n\\begin{enumerate}\n    \\item We formalize \\textbf{evidence-grounded document-level relation extraction} as a generation task for LLMs and conduct the first \\textbf{comprehensive empirical study} spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms.\n\n    \\item We characterize a \\textbf{decoupling spectrum} across optimization paradigms: RL optimization pressure is associated with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none). We use the Evidence-Decoupling Ratio (EDCR), a diagnostic that tracks misalignment between extraction and evidence capabilities, as an analytical tool throughout our study. EDCR shares Rel-Recall with Rel-F1 by construction; we interpret the observed cross-method correlation ($\\rho = -0.89$, $n = 7$) as a diagnostic pattern rather than an independent finding, and validate through per-relation analysis ($\\rho = -0.79$, $n = 76$) that avoids the shared-component concern.\n\n    \\item We identify a \\textbf{scale-dependent evidence tax}: the cost of joint evidence production varies across 1.7B, 4B, 8B, and 14B parameters, challenging the assumption that evidence generation uniformly degrades extraction quality.\n\n    \\item We establish \\textbf{RSFT with NLI-based scoring} as an effective solution, using CED or flat-NLI to select high-quality training data. RSFT improves mean Ign-F1 at all scales (+1.2 to +6.6pp) with highly reproducible training (variance compression of 7--31$\\times$ across scales), and our 1.7B RSFT model (51.19 Ign-F1) approaches 8B SFT performance (50.19), enabling deployment-efficient evidence-grounded extraction at reduced computational cost.\n\\end{enumerate}\n",
    "structuredPatch": [
      {
        "oldStart": 1,
        "oldLines": 46,
        "newStart": 1,
        "newLines": 35,
        "lines": [
          " \\section{Introduction}",
          " ",
          " Document-level relation extraction (DocRE) requires identifying semantic relations between entity pairs across multiple sentences, a task where encoder-based methods such as \\citet{zhou2021atlop} long dominated.",
          "-Recent LLM-based approaches have closed this gap: \\citet{autore2024} fine-tune LLMs with structured decomposition for end-to-end extraction, \\citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \\citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.",
          "+Recent approaches based on Large Language Models (LLMs) have closed this gap: \\citet{autore2024} fine-tune LLMs with structured decomposition for end-to-end extraction, \\citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \\citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.",
          " These methods approach or surpass encoder baselines on DocRED \\citep{yao2019docred} and Re-DocRED \\citep{tan2022redocred} in extraction accuracy.",
          " Yet every one of them outputs bare relation triplets $(e_h, r, e_t)$ without any indication of \\emph{which sentences} in the document support each prediction.",
          " In deployment contexts where predictions feed into clinical knowledge bases, legal due-diligence pipelines, or financial compliance systems, end users cannot verify a prediction without manually locating its textual basis across a multi-page document.",
          " ",
          " The absence of verifiable evidence creates a practical bottleneck.",
          "-Relation extraction outputs are consumed downstream by knowledge graph construction and human decision workflows.",
          "-When a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.",
          "-Without machine-generated evidence, this verification requires exhaustive manual review of the input document for every predicted relation.",
          "+Relation extraction outputs feed downstream knowledge graph construction and human decision workflows; when a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.",
          " Encoder-based methods have partially addressed this need: \\citet{xiao2022sais} introduce sentence-level evidence supervision as an auxiliary signal, and \\citet{ma2023dreeam} extend this with dynamic evidence retrieval through memory attention.",
          "-Both improve extraction quality \\emph{and} produce evidence annotations.",
          "-However, encoder methods now trail LLM-based approaches in extraction accuracy, and their evidence mechanisms (binary sentence classification) do not transfer to generative architectures.",
          "+Both produce evidence annotations and improve extraction quality, but encoder methods now trail LLM-based approaches in extraction accuracy.",
          " The community therefore faces a gap: the most accurate extractors provide no evidence, while the evidence-capable methods are no longer competitive.",
          " ",
          "-This gap reflects a deeper structural difference between evidence in encoder and generative frameworks.",
          "-In SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision.",
          "-The evidence signal \\emph{regularizes} the encoder and improves extraction.",
          "+This gap reflects a deeper structural difference in how evidence functions across architectures and scales.",
          "+In encoder-based methods such as SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision; the evidence signal regularizes the encoder and improves extraction at minimal cost.",
          " In LLM-based DocRE, evidence-grounded extraction requires the model to \\emph{generate} complete evidence sentences as part of its output sequence, substantially increasing output length and decoding complexity.",
          "-Evidence production in this setting is not an auxiliary signal but an additional generation burden that competes with the extraction objective for model capacity.",
          "-Whether this generation cost necessarily harms extraction, or whether the interaction is more nuanced, remains an open question: the answer may depend on model scale and optimization strategy.",
          "-This uncertainty motivates a systematic investigation of how evidence production interacts with extraction quality across model scales and optimization paradigms.",
          "+Yet the role of this generation cost is not fixed.",
          "+It depends on at least three factors: \\emph{model capacity}, where small models benefit from the implicit regularization that evidence provides while mid-scale models suffer from capacity competition and larger models absorb the overhead; \\emph{optimization paradigm}, where gradient-based methods create destructive trade-offs between evidence and extraction objectives while discrete sample selection avoids them entirely; and \\emph{training data quality}, where filtering based on Natural Language Inference (NLI) scores can transform evidence from an optimization burden into a learning scaffold.",
          "+Understanding this landscape is a prerequisite for deploying evidence-grounded extraction systems that are both accurate and verifiable.",
          " ",
          "-We formalize evidence-grounded DocRE as a structured generation task for LLMs and conduct a systematic comparison of three post-training optimization paradigms: online reinforcement learning via Group Relative Policy Optimization (GRPO; \\citealt{shao2024deepseekmath}), offline preference optimization via Direct Preference Optimization (DPO; \\citealt{rafailov2023direct}), and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR; \\citealt{zelikman2022star}).",
          "-Our experiments across 85+ configurations, spanning four model scales (1.7B to 14B), two model families, and two datasets, reveal three principal findings.",
          "-\\textbf{First}, we identify a \\emph{decoupling spectrum}: the strength of RL optimization pressure correlates with the severity of evidence-extraction decoupling.",
          "-GRPO with Quantized Low-Rank Adaptation (QLoRA; \\citealt{hu2022lora}) produces catastrophic decoupling where extraction accuracy collapses to near zero; GRPO with full-precision training shows mild decoupling; DPO exhibits gradual degradation; and RSFT maintains stable joint performance.",
          "-Catastrophic extraction collapse co-occurs with QLoRA-based GRPO training, though we note that GRPO with full-precision training (bf16, $G{=}8$) achieves EDCR below the SFT baseline, indicating that the decoupling is not inherent to online RL when sufficient precision is available.",
          "-\\textbf{Second}, we discover a \\emph{scale-dependent evidence tax}: the cost of jointly producing evidence and relations varies across model scales.",
          "-At 1.7B parameters, evidence generation provides an implicit regularization benefit (tax $-$6.2pp on a controlled evaluation subset); at 4B, the tax reaches +7.5pp; at $\\geq$8B, it approaches zero.",
          "-This pattern challenges the assumption that evidence generation uniformly harms extraction.",
          "-\\textbf{Third}, RSFT with NLI-based scoring for training data selection emerges as the most effective optimization route.",
          "-By selecting high-quality training samples through output filtering rather than applying gradient-based optimization pressure, RSFT sidesteps the multi-objective competition that destabilizes RL and preference methods.",
          "+We formalize evidence-grounded DocRE as a structured generation task and conduct a systematic comparison of three post-training paradigms: online reinforcement learning via Group Relative Policy Optimization (GRPO; \\citealt{shao2024deepseekmath}), offline preference optimization via Direct Preference Optimization (DPO; \\citealt{rafailov2023direct}), and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR; \\citealt{zelikman2022star}).",
          "+Our experiments across 85+ configurations, spanning four model scales (1.7B to 14B), two model families, and two datasets, reveal that the role of evidence generation is governed by three interacting factors.",
          "+Along the \\emph{capacity dimension}, the evidence tax varies non-monotonically: evidence generation provides implicit regularization at 1.7B ($-$6.2pp Ign-F1), imposes a substantial cost at 4B (+7.5pp), and approaches zero at $\\geq$8B parameters.",
          "+Along the \\emph{paradigm dimension}, we observe a decoupling spectrum in which the strength of optimization pressure correlates with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none); catastrophic extraction collapse co-occurs with Quantized Low-Rank Adaptation (QLoRA; \\citealt{hu2022lora}) in GRPO, though full-precision GRPO achieves decoupling below the supervised fine-tuning (SFT) baseline, which indicates that the collapse is not inherent to online RL when sufficient precision is available.",
          "+Along the \\emph{data quality dimension}, RSFT with NLI-based scoring navigates this landscape by selecting high-quality training samples through output filtering rather than applying gradient-based pressure; it improves mean Ign-F1 at all scales (+1.2 to +6.6pp) while compressing training variance 7--31$\\times$.",
          " ",
          " Our contributions are as follows:",
          " \\begin{enumerate}",
          "-    \\item We formalize \\textbf{evidence-grounded document-level relation extraction} as a generation task for LLMs and conduct the first \\textbf{comprehensive empirical study} spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms.",
          "+    \\item We map the \\textbf{evidence generation landscape} through a comprehensive empirical study spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms. We identify a \\textbf{scale-dependent evidence tax} that varies from beneficial ($-$6.2pp at 1.7B) to costly (+7.5pp at 4B) to negligible ($\\geq$8B). This pattern challenges the assumption that evidence generation uniformly harms extraction.",
          " ",
          "-    \\item We characterize a \\textbf{decoupling spectrum} across optimization paradigms: RL optimization pressure is associated with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none). We use the Evidence-Decoupling Ratio (EDCR), a diagnostic that tracks misalignment between extraction and evidence capabilities, as an analytical tool throughout our study. EDCR shares Rel-Recall with Rel-F1 by construction; we interpret the observed cross-method correlation ($\\rho = -0.89$, $n = 7$) as a diagnostic pattern rather than an independent finding, and validate through per-relation analysis ($\\rho = -0.79$, $n = 76$) that avoids the shared-component concern.",
          "+    \\item We characterize a \\textbf{decoupling spectrum} that explains why gradient-based paradigms fail at joint evidence-and-extraction generation: RL optimization pressure correlates with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none). We introduce the Evidence-Decoupling Ratio (EDCR) as a diagnostic metric, validated through per-relation analysis ($\\rho = -0.79$, $n = 76$, $p < 0.0001$).",
          " ",
          "-    \\item We identify a \\textbf{scale-dependent evidence tax}: the cost of joint evidence production varies across 1.7B, 4B, 8B, and 14B parameters, challenging the assumption that evidence generation uniformly degrades extraction quality.",
          "-",
          "-    \\item We establish \\textbf{RSFT with NLI-based scoring} as an effective solution, using CED or flat-NLI to select high-quality training data. RSFT improves mean Ign-F1 at all scales (+1.2 to +6.6pp) with highly reproducible training (variance compression of 7--31$\\times$ across scales), and our 1.7B RSFT model (51.19 Ign-F1) approaches 8B SFT performance (50.19), enabling deployment-efficient evidence-grounded extraction at reduced computational cost.",
          "+    \\item We establish \\textbf{RSFT with NLI-based scoring} as an effective navigation strategy for this landscape. RSFT improves mean Ign-F1 at all scales (+1.2 to +6.6pp) with 7--31$\\times$ variance compression, and our 1.7B RSFT model (51.19 Ign-F1, std 0.09pp) approaches 8B SFT performance (50.19, std 3.72pp) while being 4.7$\\times$ smaller and substantially more predictable. This combination enables deployment-efficient evidence-grounded extraction.",
          " \\end{enumerate}"
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

_source line 15_

<details><summary>Logged reasoning block</summary>

```text
Let me verify the edit by reading the file.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "5104eebe-f641-42c4-9efa-79d7036ed215",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GryyraFsPWgB74DaT4AbEX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14317,
      "cache_read_input_tokens": 39288,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14317
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

_source line 16_

Let me verify the result.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "f14c424d-4534-4467-82b2-abb4fe7edbd8",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GryyraFsPWgB74DaT4AbEX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14317,
      "cache_read_input_tokens": 39288,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14317
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

_source line 17_

<details open><summary>🔧 Tool call — Read · `toolu_01Uay9GkL7sFRtotXcYFhxHV`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "186b7aab-4b6a-42bb-88af-e56fd1688a8d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01GryyraFsPWgB74DaT4AbEX",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 14317,
      "cache_read_input_tokens": 39288,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 14317
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

_source line 18 · 2026-05-20T10:11:27.177Z_

<details><summary>↩ Tool result · `toolu_01Uay9GkL7sFRtotXcYFhxHV`</summary>

```text
1	\section{Introduction}
2	
3	Document-level relation extraction (DocRE) requires identifying semantic relations between entity pairs across multiple sentences, a task where encoder-based methods such as \citet{zhou2021atlop} long dominated.
4	Recent approaches based on Large Language Models (LLMs) have closed this gap: \citet{autore2024} fine-tune LLMs with structured decomposition for end-to-end extraction, \citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.
5	These methods approach or surpass encoder baselines on DocRED \citep{yao2019docred} and Re-DocRED \citep{tan2022redocred} in extraction accuracy.
6	Yet every one of them outputs bare relation triplets $(e_h, r, e_t)$ without any indication of \emph{which sentences} in the document support each prediction.
7	In deployment contexts where predictions feed into clinical knowledge bases, legal due-diligence pipelines, or financial compliance systems, end users cannot verify a prediction without manually locating its textual basis across a multi-page document.
8	
9	The absence of verifiable evidence creates a practical bottleneck.
10	Relation extraction outputs feed downstream knowledge graph construction and human decision workflows; when a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.
11	Encoder-based methods have partially addressed this need: \citet{xiao2022sais} introduce sentence-level evidence supervision as an auxiliary signal, and \citet{ma2023dreeam} extend this with dynamic evidence retrieval through memory attention.
12	Both produce evidence annotations and improve extraction quality, but encoder methods now trail LLM-based approaches in extraction accuracy.
13	The community therefore faces a gap: the most accurate extractors provide no evidence, while the evidence-capable methods are no longer competitive.
14	
15	This gap reflects a deeper structural difference in how evidence functions across architectures and scales.
16	In encoder-based methods such as SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision; the evidence signal regularizes the encoder and improves extraction at minimal cost.
17	In LLM-based DocRE, evidence-grounded extraction requires the model to \emph{generate} complete evidence sentences as part of its output sequence, substantially increasing output length and decoding complexity.
18	Yet the role of this generation cost is not fixed.
19	It depends on at least three factors: \emph{model capacity}, where small models benefit from the implicit regularization that evidence provides while mid-scale models suffer from capacity competition and larger models absorb the overhead; \emph{optimization paradigm}, where gradient-based methods create destructive trade-offs between evidence and extraction objectives while discrete sample selection avoids them entirely; and \emph{training data quality}, where filtering based on Natural Language Inference (NLI) scores can transform evidence from an optimization burden into a learning scaffold.
20	Understanding this landscape is a prerequisite for deploying evidence-grounded extraction systems that are both accurate and verifiable.
21	
22	We formalize evidence-grounded DocRE as a structured generation task and conduct a systematic comparison of three post-training paradigms: online reinforcement learning via Group Relative Policy Optimization (GRPO; \citealt{shao2024deepseekmath}), offline preference optimization via Direct Preference Optimization (DPO; \citealt{rafailov2023direct}), and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR; \citealt{zelikman2022star}).
23	Our experiments across 85+ configurations, spanning four model scales (1.7B to 14B), two model families, and two datasets, reveal that the role of evidence generation is governed by three interacting factors.
24	Along the \emph{capacity dimension}, the evidence tax varies non-monotonically: evidence generation provides implicit regularization at 1.7B ($-$6.2pp Ign-F1), imposes a substantial cost at 4B (+7.5pp), and approaches zero at $\geq$8B parameters.
25	Along the \emph{paradigm dimension}, we observe a decoupling spectrum in which the strength of optimization pressure correlates with evidence-extraction decoupling severity (GRPO catastrophic $\rightarrow$ DPO gradual $\rightarrow$ RSFT none); catastrophic extraction collapse co-occurs with Quantized Low-Rank Adaptation (QLoRA; \citealt{hu2022lora}) in GRPO, though full-precision GRPO achieves decoupling below the supervised fine-tuning (SFT) baseline, which indicates that the collapse is not inherent to online RL when sufficient precision is available.
26	Along the \emph{data quality dimension}, RSFT with NLI-based scoring navigates this landscape by selecting high-quality training samples through output filtering rather than applying gradient-based pressure; it improves mean Ign-F1 at all scales (+1.2 to +6.6pp) while compressing training variance 7--31$\times$.
27	
28	Our contributions are as follows:
29	\begin{enumerate}
30	    \item We map the \textbf{evidence generation landscape} through a comprehensive empirical study spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms. We identify a \textbf{scale-dependent evidence tax} that varies from beneficial ($-$6.2pp at 1.7B) to costly (+7.5pp at 4B) to negligible ($\geq$8B). This pattern challenges the assumption that evidence generation uniformly harms extraction.
31	
32	    \item We characterize a \textbf{decoupling spectrum} that explains why gradient-based paradigms fail at joint evidence-and-extraction generation: RL optimization pressure correlates with evidence-extraction decoupling severity (GRPO catastrophic $\rightarrow$ DPO gradual $\rightarrow$ RSFT none). We introduce the Evidence-Decoupling Ratio (EDCR) as a diagnostic metric, validated through per-relation analysis ($\rho = -0.79$, $n = 76$, $p < 0.0001$).
33	
34	    \item We establish \textbf{RSFT with NLI-based scoring} as an effective navigation strategy for this landscape. RSFT improves mean Ign-F1 at all scales (+1.2 to +6.6pp) with 7--31$\times$ variance compression, and our 1.7B RSFT model (51.19 Ign-F1, std 0.09pp) approaches 8B SFT performance (50.19, std 3.72pp) while being 4.7$\times$ smaller and substantially more predictable. This combination enables deployment-efficient evidence-grounded extraction.
35	\end{enumerate}
36	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "33917365-c7f2-4b8d-a698-9102c7feab21",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-idea_gen_0513_6/projects/faith-evidence-ie/docs/paper/sections/introduction.tex",
      "content": "\\section{Introduction}\n\nDocument-level relation extraction (DocRE) requires identifying semantic relations between entity pairs across multiple sentences, a task where encoder-based methods such as \\citet{zhou2021atlop} long dominated.\nRecent approaches based on Large Language Models (LLMs) have closed this gap: \\citet{autore2024} fine-tune LLMs with structured decomposition for end-to-end extraction, \\citet{xu2024lmrc} frame it as multi-choice reading comprehension, and \\citet{chen2025docksrag} combine retrieval-augmented generation with structured knowledge.\nThese methods approach or surpass encoder baselines on DocRED \\citep{yao2019docred} and Re-DocRED \\citep{tan2022redocred} in extraction accuracy.\nYet every one of them outputs bare relation triplets $(e_h, r, e_t)$ without any indication of \\emph{which sentences} in the document support each prediction.\nIn deployment contexts where predictions feed into clinical knowledge bases, legal due-diligence pipelines, or financial compliance systems, end users cannot verify a prediction without manually locating its textual basis across a multi-page document.\n\nThe absence of verifiable evidence creates a practical bottleneck.\nRelation extraction outputs feed downstream knowledge graph construction and human decision workflows; when a system predicts that a drug interacts with a gene, or that a contract clause implies a liability, practitioners must trace each prediction back to source text before acting on it.\nEncoder-based methods have partially addressed this need: \\citet{xiao2022sais} introduce sentence-level evidence supervision as an auxiliary signal, and \\citet{ma2023dreeam} extend this with dynamic evidence retrieval through memory attention.\nBoth produce evidence annotations and improve extraction quality, but encoder methods now trail LLM-based approaches in extraction accuracy.\nThe community therefore faces a gap: the most accurate extractors provide no evidence, while the evidence-capable methods are no longer competitive.\n\nThis gap reflects a deeper structural difference in how evidence functions across architectures and scales.\nIn encoder-based methods such as SAIS and DREEAM, evidence retrieval is a binary classification task (does sentence $s_i$ support relation $r$?) that serves as auxiliary supervision; the evidence signal regularizes the encoder and improves extraction at minimal cost.\nIn LLM-based DocRE, evidence-grounded extraction requires the model to \\emph{generate} complete evidence sentences as part of its output sequence, substantially increasing output length and decoding complexity.\nYet the role of this generation cost is not fixed.\nIt depends on at least three factors: \\emph{model capacity}, where small models benefit from the implicit regularization that evidence provides while mid-scale models suffer from capacity competition and larger models absorb the overhead; \\emph{optimization paradigm}, where gradient-based methods create destructive trade-offs between evidence and extraction objectives while discrete sample selection avoids them entirely; and \\emph{training data quality}, where filtering based on Natural Language Inference (NLI) scores can transform evidence from an optimization burden into a learning scaffold.\nUnderstanding this landscape is a prerequisite for deploying evidence-grounded extraction systems that are both accurate and verifiable.\n\nWe formalize evidence-grounded DocRE as a structured generation task and conduct a systematic comparison of three post-training paradigms: online reinforcement learning via Group Relative Policy Optimization (GRPO; \\citealt{shao2024deepseekmath}), offline preference optimization via Direct Preference Optimization (DPO; \\citealt{rafailov2023direct}), and offline reinforcement learning via Rejection Sampling Fine-Tuning (RSFT, building on STaR; \\citealt{zelikman2022star}).\nOur experiments across 85+ configurations, spanning four model scales (1.7B to 14B), two model families, and two datasets, reveal that the role of evidence generation is governed by three interacting factors.\nAlong the \\emph{capacity dimension}, the evidence tax varies non-monotonically: evidence generation provides implicit regularization at 1.7B ($-$6.2pp Ign-F1), imposes a substantial cost at 4B (+7.5pp), and approaches zero at $\\geq$8B parameters.\nAlong the \\emph{paradigm dimension}, we observe a decoupling spectrum in which the strength of optimization pressure correlates with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none); catastrophic extraction collapse co-occurs with Quantized Low-Rank Adaptation (QLoRA; \\citealt{hu2022lora}) in GRPO, though full-precision GRPO achieves decoupling below the supervised fine-tuning (SFT) baseline, which indicates that the collapse is not inherent to online RL when sufficient precision is available.\nAlong the \\emph{data quality dimension}, RSFT with NLI-based scoring navigates this landscape by selecting high-quality training samples through output filtering rather than applying gradient-based pressure; it improves mean Ign-F1 at all scales (+1.2 to +6.6pp) while compressing training variance 7--31$\\times$.\n\nOur contributions are as follows:\n\\begin{enumerate}\n    \\item We map the \\textbf{evidence generation landscape} through a comprehensive empirical study spanning 85+ experiments across four model scales, two model families, two datasets (DocRED, Re-DocRED), and three optimization paradigms. We identify a \\textbf{scale-dependent evidence tax} that varies from beneficial ($-$6.2pp at 1.7B) to costly (+7.5pp at 4B) to negligible ($\\geq$8B). This pattern challenges the assumption that evidence generation uniformly harms extraction.\n\n    \\item We characterize a \\textbf{decoupling spectrum} that explains why gradient-based paradigms fail at joint evidence-and-extraction generation: RL optimization pressure correlates with evidence-extraction decoupling severity (GRPO catastrophic $\\rightarrow$ DPO gradual $\\rightarrow$ RSFT none). We introduce the Evidence-Decoupling Ratio (EDCR) as a diagnostic metric, validated through per-relation analysis ($\\rho = -0.79$, $n = 76$, $p < 0.0001$).\n\n    \\item We establish \\textbf{RSFT with NLI-based scoring} as an effective navigation strategy for this landscape. RSFT improves mean Ign-F1 at all scales (+1.2 to +6.6pp) with 7--31$\\times$ variance compression, and our 1.7B RSFT model (51.19 Ign-F1, std 0.09pp) approaches 8B SFT performance (50.19, std 3.72pp) while being 4.7$\\times$ smaller and substantially more predictable. This combination enables deployment-efficient evidence-grounded extraction.\n\\end{enumerate}\n",
      "numLines": 36,
      "startLine": 1,
      "totalLines": 36
    }
  }
}
```

</details>

---

### Assistant

_source line 19_

<details><summary>Logged reasoning block</summary>

```text
The file looks good. Let me do a quick sanity check:

1. No em-dashes (—): ✓ (no — in the file)
2. No -ing phrase endings: ✓ (checked all sentence endings)
3. No banned words: ✓
4. All citations preserved: \citet{zhou2021atlop}, \citet{autore2024}, \citet{xu2024lmrc}, \citet{chen2025docksrag}, \citep{yao2019docred}, \citep{tan2022redocred}, \citet{xiao2022sais}, \citet{ma2023dreeam}, \citealt{shao2024deepseekmath}, \citealt{rafailov2023direct}, \citealt{zelikman2022star}, \citealt{hu2022lora} ✓


5. No fabricated citations ✓
6. Abbreviations defined: LLMs (line 4), GRPO (line 22), DPO (line 22), RSFT (line 22), QLoRA (line 25), SFT (line 25), EDCR (line 32), NLI (line 19), DocRE (line 3) ✓
7. 3 contributions (not 4) ✓
8. Narrative reframe: "three interacting factors" not "three findings" ✓
9. Paragraph 3 is the new landscape paragraph ✓
10. EDCR rho=-0.89 is NOT mentioned (only per-relation validation with rho=-0.79) ✓

The structure flows from problem and LLM progress, through the evidence gap and encoder limitations, into evidence as a landscape concept, then our study's three facets, and finally the contributions framed through those same three facets.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "d5ef352f-1072-4097-a036-78463cf3e42a",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015X2237XTnmMcAJ9LvWXxyc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1834,
      "cache_read_input_tokens": 53605,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1834
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

_source line 20_

已完成。主要变更：

- **¶1**: 保留核心内容，增加 LLM 缩写定义
- **¶2**: 原来两段合并为一段，压缩冗余
- **¶3（新）**: 叙事升级核心段落，将 evidence 的角色从"固定代价"重构为依赖 model capacity / optimization paradigm / data quality 三因素的 landscape
- **¶4**: "three principal findings" → "three interacting factors"，按 capacity / paradigm / data quality 三个维度组织
- **¶5**: 4 个 contribution 合并为 3 个 facet（landscape mapping + decoupling spectrum + RSFT navigation strategy），EDCR 仅引用 per-relation validation（ρ=−0.79, n=76），不再出现 cross-method ρ=−0.89

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "uuid": "02b8114b-5d0e-4c5e-be25-74067c841a4d",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_015X2237XTnmMcAJ9LvWXxyc",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 1834,
      "cache_read_input_tokens": 53605,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 1834
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

_source line 21_

已完成。主要变更：

- **¶1**: 保留核心内容，增加 LLM 缩写定义
- **¶2**: 原来两段合并为一段，压缩冗余
- **¶3（新）**: 叙事升级核心段落，将 evidence 的角色从"固定代价"重构为依赖 model capacity / optimization paradigm / data quality 三因素的 landscape
- **¶4**: "three principal findings" → "three interacting factors"，按 capacity / paradigm / data quality 三个维度组织
- **¶5**: 4 个 contribution 合并为 3 个 facet（landscape mapping + decoupling spectrum + RSFT navigation strategy），EDCR 仅引用 per-relation validation（ρ=−0.79, n=76），不再出现 cross-method ρ=−0.89

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 248024,
  "duration_api_ms": 249172,
  "num_turns": 6,
  "stop_reason": "end_turn",
  "session_id": "2c52d262-c73d-4882-ac5c-4fe9260c1b76",
  "total_cost_usd": 0.7261125,
  "usage": {
    "input_tokens": 5,
    "cache_creation_input_tokens": 43598,
    "cache_read_input_tokens": 130970,
    "output_tokens": 15386,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 43598,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 784,
        "cache_read_input_tokens": 53605,
        "cache_creation_input_tokens": 1834,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 1834
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 3370,
      "outputTokens": 19,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.003465,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 5,
      "outputTokens": 15386,
      "cacheReadInputTokens": 130970,
      "cacheCreationInputTokens": 43598,
      "webSearchRequests": 0,
      "costUSD": 0.7226475000000001,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "8a1fc9f2-4929-4c35-877c-66804b2ead96"
}
```

</details>

---
