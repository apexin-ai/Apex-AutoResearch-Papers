# paper writing abstract

**Why Token Pruning Crashes Some Robot Policies but Not Others: Vision Connectors and VLA Token Compressibility** · Worker execution logs

This page is a human-readable rendering of one source record. It preserves the recorded order and wording; the linked JSON keeps the complete machine-readable structure.

## Record overview

- **Events:** 26
- **Recorded user turns:** 0
- **Tool calls:** 8
- **Original source:** `logs/workers/worker_paper_writing_abstract_20260523T020351.log`
- **Structured JSON:** [`fa75a7fb995132116662.json`](../../sessions/fa/fa75a7fb995132116662.json)

## Before a recorded user message

26 recorded events

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
  "cwd": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress",
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
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
  "uuid": "74b632d3-1715-4b5f-86c5-e1827ff27cb6",
  "memory_paths": {
    "auto": "/home/ubuntu/.claude-account-2/projects/-home-ubuntu--agent-ml-research-be-idea-gen-0515-2-projects-importance-margin-vla-compress/memory/"
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
    "resetsAt": 1779513000,
    "rateLimitType": "five_hour",
    "overageStatus": "rejected",
    "overageDisabledReason": "org_level_disabled",
    "isUsingOverage": false
  },
  "uuid": "c404b5e0-ae6e-4e1b-95f9-b74d9a2ed184",
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7"
}
```

---

### Assistant

_source line 4_

I'll read the skill files and reference papers first.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "9a2c5a8c-0343-42bf-8eb1-2c867b919463",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BGzF2o1omhUqakkDL9zK59",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12602,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12602
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

<details open><summary>🔧 Tool call — Read · `toolu_01Wy4N98n6bAGPZhvjN6XfHe`</summary>

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
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "67fd7989-1696-4e8f-8017-61af256f2d1f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BGzF2o1omhUqakkDL9zK59",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12602,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12602
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

_source line 6 · 2026-05-23T02:04:03.917Z_

<details><summary>↩ Tool result · `toolu_01Wy4N98n6bAGPZhvjN6XfHe`</summary>

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
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "5864d1b5-aebb-49d2-beb6-3311497c358d",
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

<details open><summary>🔧 Tool call — Read · `toolu_013KuhgxsaZyfHto8BCJaLSz`</summary>

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
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "9618c32d-9d99-4c74-8c3d-0002b3913d00",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BGzF2o1omhUqakkDL9zK59",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12602,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12602
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

_source line 8 · 2026-05-23T02:04:04.405Z_

<details><summary>↩ Tool result · `toolu_013KuhgxsaZyfHto8BCJaLSz`</summary>

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
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "44e6bb25-089a-437f-ad23-f812086cd2f0",
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

<details open><summary>🔧 Tool call — Read · `toolu_013aEu8D1Wqs9kL9gFuTBBa9`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/introduction.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "6abe0c9a-6c01-4661-bc12-b9436c5f93ad",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BGzF2o1omhUqakkDL9zK59",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12602,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12602
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

_source line 10 · 2026-05-23T02:04:04.980Z_

<details><summary>↩ Tool result · `toolu_013aEu8D1Wqs9kL9gFuTBBa9`</summary>

```text
1	\section{Introduction}
2	\label{sec:introduction}
3	
4	Remove 5\% of vision tokens from SmolVLA and its success rate collapses from 59.2\% to 0.0\% across all task suites and pruning methods. Apply the same 5\% reduction to $\pi_0.5$ and it retains 98.2\%. Both are Vision-Language-Action (VLA) models built on a Vision Transformer (ViT) encoder feeding tokens through a connector into a language model backbone; the critical difference is not model scale (450M vs.\ 4B parameters) but the connector architecture. Token pruning is well-established for image classification, where DynamicViT~\cite{rao2021dynamicvit}, Token Merging~\cite{bolya2023tome}, and EViT~\cite{liang2022evit} reduce computation by 50\% or more with minimal accuracy loss. A growing body of work extends these techniques to VLAs: VLA-IAP~\cite{wang2026vlaiap}, VLA-Cache~\cite{hsu2025vlacache}, EfficientVLA~\cite{yang2025efficientvla}, and VLA-Pruner~\cite{liu2025vlapruner} each demonstrate efficiency gains on individual architectures.
5	
6	These methods implicitly assume that token pruning effectiveness transfers across VLA designs. Yet current VLAs employ fundamentally different vision connectors: linear projections~\cite{black2024pi0}, multi-layer MLP projectors~\cite{kim2024openvla}, pixel-shuffle spatial folding~\cite{shukor2025smolvla}, and learned encoders with cross-token self-attention~\cite{zheng2025xvla}. Each connector imposes distinct constraints on how visual information is distributed across tokens. Deploying a pruning method validated on one architecture to a different connector type risks silent degradation or, as the SmolVLA result above illustrates, complete loss of manipulation capability. No prior work systematically evaluates pruning robustness across both connector architectures and task complexity distributions, and the factor that determines whether a given VLA tolerates token removal remains uncharacterized.
7	
8	We propose a two-axis analysis of VLA token compressibility: pruning sensitivity as a function of connector coupling and task complexity (Figure~\ref{fig:teaser}). Along the coupling axis, token-independent connectors (linear projections, MLP projectors) degrade gracefully because each output token encodes information from a single input patch. Token-entangling connectors produce qualitatively different failures: SmolVLA's pixel-shuffle ($4{\times}4$ spatial folding) collapses to 0.0\% success rate at every retention ratio tested, while X-VLA's 12-layer BART encoder exhibits sharp, threshold-dependent drops. Along the task complexity axis, multi-step tasks amplify degradation in a connector-dependent manner. At retention ratio $k{=}0.9$, X-VLA retains its full 99.2\% baseline on single-step Object manipulation but loses 27.8 percentage points on multi-step Goal-conditioned tasks, a gap driven entirely by task demands at the same retention ratio. The coefficient of variation (CV) of post-connector token L2 norms captures connector coupling on a continuous spectrum from 0.038 ($\pi_0$, linear projection) to 0.314 (SmolVLA, pixel-shuffle) and correlates with both pruning tolerance and the retention threshold at which pruning method choice becomes critical. At $k{=}0.95$, $\pi_0.5$ (CV$\,{=}\,$0.055) exhibits method gaps of 28.8 percentage points on LIBERO-Object and 21.4 percentage points on Spatial, while X-VLA (CV$\,{=}\,$0.151) shows a 1.4 percentage point gap on the same Spatial suite---a 15$\times$ difference in method sensitivity.
9	
10	For pixel-shuffle connectors where all pruning strategies yield 0.0\% success rate, we introduce Vision Token Re-encoder (VTR), a lightweight cross-attention module (${\sim}$22M parameters, approximately 5\% of SmolVLA) that recovers over 60\% success rate through learned re-encoding at 75\% token compression. The VTR performance curve across output token counts $M$ is flat ($M{=}16$ matches $M{=}128$ within 1.1 percentage points), which confirms that learned re-encoding of spatially entangled representations, not the compression ratio, is the operative factor.
11	
12	Our contributions are:
13	\begin{itemize}
14	    \item A two-axis compressibility analysis validated across six VLA models (450M to 7B parameters) on four LIBERO~\cite{liu2023libero} task suites, which reveals connector architecture and task complexity as interacting determinants of pruning robustness.
15	    \item CV of token L2 norms as a single-pass diagnostic that correlates with both pruning tolerance and method sensitivity, and enables connector-appropriate compression strategy selection without downstream evaluation.
16	    \item Vision Token Re-encoder (VTR), a learned re-encoding module that recovers pixel-shuffle VLAs from 0.0\% to over 60\% success rate at 75\% token compression, where all hard pruning methods fail.
17	\end{itemize}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "02c39e09-a349-4e49-bd8d-125d960ba119",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/introduction.tex",
      "content": "\\section{Introduction}\n\\label{sec:introduction}\n\nRemove 5\\% of vision tokens from SmolVLA and its success rate collapses from 59.2\\% to 0.0\\% across all task suites and pruning methods. Apply the same 5\\% reduction to $\\pi_0.5$ and it retains 98.2\\%. Both are Vision-Language-Action (VLA) models built on a Vision Transformer (ViT) encoder feeding tokens through a connector into a language model backbone; the critical difference is not model scale (450M vs.\\ 4B parameters) but the connector architecture. Token pruning is well-established for image classification, where DynamicViT~\\cite{rao2021dynamicvit}, Token Merging~\\cite{bolya2023tome}, and EViT~\\cite{liang2022evit} reduce computation by 50\\% or more with minimal accuracy loss. A growing body of work extends these techniques to VLAs: VLA-IAP~\\cite{wang2026vlaiap}, VLA-Cache~\\cite{hsu2025vlacache}, EfficientVLA~\\cite{yang2025efficientvla}, and VLA-Pruner~\\cite{liu2025vlapruner} each demonstrate efficiency gains on individual architectures.\n\nThese methods implicitly assume that token pruning effectiveness transfers across VLA designs. Yet current VLAs employ fundamentally different vision connectors: linear projections~\\cite{black2024pi0}, multi-layer MLP projectors~\\cite{kim2024openvla}, pixel-shuffle spatial folding~\\cite{shukor2025smolvla}, and learned encoders with cross-token self-attention~\\cite{zheng2025xvla}. Each connector imposes distinct constraints on how visual information is distributed across tokens. Deploying a pruning method validated on one architecture to a different connector type risks silent degradation or, as the SmolVLA result above illustrates, complete loss of manipulation capability. No prior work systematically evaluates pruning robustness across both connector architectures and task complexity distributions, and the factor that determines whether a given VLA tolerates token removal remains uncharacterized.\n\nWe propose a two-axis analysis of VLA token compressibility: pruning sensitivity as a function of connector coupling and task complexity (Figure~\\ref{fig:teaser}). Along the coupling axis, token-independent connectors (linear projections, MLP projectors) degrade gracefully because each output token encodes information from a single input patch. Token-entangling connectors produce qualitatively different failures: SmolVLA's pixel-shuffle ($4{\\times}4$ spatial folding) collapses to 0.0\\% success rate at every retention ratio tested, while X-VLA's 12-layer BART encoder exhibits sharp, threshold-dependent drops. Along the task complexity axis, multi-step tasks amplify degradation in a connector-dependent manner. At retention ratio $k{=}0.9$, X-VLA retains its full 99.2\\% baseline on single-step Object manipulation but loses 27.8 percentage points on multi-step Goal-conditioned tasks, a gap driven entirely by task demands at the same retention ratio. The coefficient of variation (CV) of post-connector token L2 norms captures connector coupling on a continuous spectrum from 0.038 ($\\pi_0$, linear projection) to 0.314 (SmolVLA, pixel-shuffle) and correlates with both pruning tolerance and the retention threshold at which pruning method choice becomes critical. At $k{=}0.95$, $\\pi_0.5$ (CV$\\,{=}\\,$0.055) exhibits method gaps of 28.8 percentage points on LIBERO-Object and 21.4 percentage points on Spatial, while X-VLA (CV$\\,{=}\\,$0.151) shows a 1.4 percentage point gap on the same Spatial suite---a 15$\\times$ difference in method sensitivity.\n\nFor pixel-shuffle connectors where all pruning strategies yield 0.0\\% success rate, we introduce Vision Token Re-encoder (VTR), a lightweight cross-attention module (${\\sim}$22M parameters, approximately 5\\% of SmolVLA) that recovers over 60\\% success rate through learned re-encoding at 75\\% token compression. The VTR performance curve across output token counts $M$ is flat ($M{=}16$ matches $M{=}128$ within 1.1 percentage points), which confirms that learned re-encoding of spatially entangled representations, not the compression ratio, is the operative factor.\n\nOur contributions are:\n\\begin{itemize}\n    \\item A two-axis compressibility analysis validated across six VLA models (450M to 7B parameters) on four LIBERO~\\cite{liu2023libero} task suites, which reveals connector architecture and task complexity as interacting determinants of pruning robustness.\n    \\item CV of token L2 norms as a single-pass diagnostic that correlates with both pruning tolerance and method sensitivity, and enables connector-appropriate compression strategy selection without downstream evaluation.\n    \\item Vision Token Re-encoder (VTR), a learned re-encoding module that recovers pixel-shuffle VLAs from 0.0\\% to over 60\\% success rate at 75\\% token compression, where all hard pruning methods fail.\n\\end{itemize}",
      "numLines": 17,
      "startLine": 1,
      "totalLines": 17
    }
  }
}
```

</details>

---

### Tool call

_source line 11_

<details open><summary>🔧 Tool call — Read · `toolu_01KViXrZmtccobdSPmFMPeUH`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/conclusion.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "5257b010-cadd-4e26-a488-dcaee7ca6818",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BGzF2o1omhUqakkDL9zK59",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12602,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12602
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

_source line 12 · 2026-05-23T02:04:05.348Z_

<details><summary>↩ Tool result · `toolu_01KViXrZmtccobdSPmFMPeUH`</summary>

```text
1	\section{Conclusion}
2	\label{sec:conclusion}
3	
4	Vision token pruning in VLAs is not a uniform operation: its outcome depends on the interaction between connector architecture and task complexity. Evaluating six VLA models (450M to 7B parameters) across four LIBERO task suites, we find that connector coupling is the primary determinant of pruning robustness. Token-independent connectors (linear projections, MLP projectors) degrade proportionally to the fraction removed, while token-entangling connectors (pixel-shuffle folding, BART encoder) exhibit task-amplified collapse. SmolVLA's pixel-shuffle connector produces 0.0\% success rate when just 5\% of tokens are removed; X-VLA retains its full 99.2\% baseline on Object at $k{=}0.9$ but loses 27.8 percentage points on Goal at the same ratio. The coefficient of variation of post-connector token L2 norms captures this spectrum as a single-pass diagnostic: models with CV$\,{=}\,$0.055 show $15{\times}$ greater method sensitivity than those with CV$\,{\geq}\,$0.15, and this metric correlates with both pruning tolerance and the retention threshold at which method choice becomes critical. For architectures where all pruning strategies fail, Vision Token Re-encoder recovers pixel-shuffle VLAs from 0.0\% to over 60\% success rate at 75\% compression through learned re-encoding.
5	
6	These findings carry practical implications: computing CV before deployment can guide compression strategy selection without costly closed-loop evaluation. Two directions remain open. Real-robot validation is needed to confirm that the connector-complexity interaction observed in simulation transfers to physical manipulation. Adaptive per-task pruning schedules, where the retention ratio adjusts to estimated task complexity, could further close the gap between token-independent and token-entangling architectures.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "f500f15f-efaf-4cc6-a089-3f0244908e3d",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/conclusion.tex",
      "content": "\\section{Conclusion}\n\\label{sec:conclusion}\n\nVision token pruning in VLAs is not a uniform operation: its outcome depends on the interaction between connector architecture and task complexity. Evaluating six VLA models (450M to 7B parameters) across four LIBERO task suites, we find that connector coupling is the primary determinant of pruning robustness. Token-independent connectors (linear projections, MLP projectors) degrade proportionally to the fraction removed, while token-entangling connectors (pixel-shuffle folding, BART encoder) exhibit task-amplified collapse. SmolVLA's pixel-shuffle connector produces 0.0\\% success rate when just 5\\% of tokens are removed; X-VLA retains its full 99.2\\% baseline on Object at $k{=}0.9$ but loses 27.8 percentage points on Goal at the same ratio. The coefficient of variation of post-connector token L2 norms captures this spectrum as a single-pass diagnostic: models with CV$\\,{=}\\,$0.055 show $15{\\times}$ greater method sensitivity than those with CV$\\,{\\geq}\\,$0.15, and this metric correlates with both pruning tolerance and the retention threshold at which method choice becomes critical. For architectures where all pruning strategies fail, Vision Token Re-encoder recovers pixel-shuffle VLAs from 0.0\\% to over 60\\% success rate at 75\\% compression through learned re-encoding.\n\nThese findings carry practical implications: computing CV before deployment can guide compression strategy selection without costly closed-loop evaluation. Two directions remain open. Real-robot validation is needed to confirm that the connector-complexity interaction observed in simulation transfers to physical manipulation. Adaptive per-task pruning schedules, where the retention ratio adjusts to estimated task complexity, could further close the gap between token-independent and token-entangling architectures.",
      "numLines": 6,
      "startLine": 1,
      "totalLines": 6
    }
  }
}
```

</details>

---

### Tool call

_source line 13_

<details open><summary>🔧 Tool call — Read · `toolu_018MawNcAxXXxEkNGZvA1GHy`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/experiments.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "5e3ba536-bf8b-4d26-9593-6e10849ede32",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01BGzF2o1omhUqakkDL9zK59",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 3,
      "cache_creation_input_tokens": 12602,
      "cache_read_input_tokens": 11841,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 12602
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

_source line 14 · 2026-05-23T02:04:05.693Z_

<details><summary>↩ Tool result · `toolu_018MawNcAxXXxEkNGZvA1GHy`</summary>

```text
1	\section{Experiments}
2	\label{sec:experiments}
3	
4	\subsection{Experimental Setup}
5	\label{sec:exp_setup}
6	
7	We evaluate vision token pruning across six VLA models spanning three connector families on the LIBERO benchmark~\cite{liu2023libero}. LIBERO provides four task suites of increasing complexity: Object (object manipulation), Spatial (spatial reasoning), Goal (goal-conditioned tasks), and Long (long-horizon multi-step tasks). Each suite contains 10 tasks evaluated over 50 episodes, yielding 500 episodes per condition.
8	
9	Four models are evaluated in closed-loop robotic control: $\pi_0.5$~\cite{black2025pi05} (4B parameters, linear projection with $\times\!\sqrt{d}$ scaling, 768 tokens from three cameras, CV$\,{=}\,$0.055), X-VLA~\cite{zheng2025xvla} (880M, linear projection followed by a 12-layer BART encoder~\cite{lewis2020bart}, 50 tokens, CV$\,{=}\,$0.151), OpenVLA~\cite{kim2024openvla} (7B, three-layer MLP projector, 256 tokens, CV$\,{=}\,$0.215), and SmolVLA~\cite{shukor2025smolvla} (450M, pixel-shuffle $4{\times}4$ folding, 128 tokens, CV$\,{=}\,$0.314). Two additional models are analyzed via offline metrics only: $\pi_0$~\cite{black2024pi0} (3.3B, linear projection, 256 tokens, CV$\,{=}\,$0.038) and OFT~\cite{kim2025openoft} (7B, MLP projector, 512 tokens, CV$\,{=}\,$0.219). Table~\ref{tab:model_properties} summarizes model properties and connector details.
10	
11	The pruning protocol applies post-connector token pruning at retention ratios $k \in \{0.3, 0.5, 0.7, 0.85, 0.9, 0.95\}$. Two strategies bracket the robustness range: \textbf{L2 norm selection} ranks tokens by L2 norm and retains the top-$k$ fraction, providing an importance-based favorable test; \textbf{random subsampling} selects tokens uniformly at random, providing a conservative lower bound. Both strategies physically remove tokens and re-index position IDs. All results report mean success rate (SR) over 500 episodes with Wilson 95\% confidence intervals for single-seed conditions.
12	
13	\subsection{Two-Axis Framework Overview}
14	\label{sec:two_axis}
15	
16	The pruning response of a VLA model depends on two axes: the degree of token independence imposed by the vision connector, and the complexity of the downstream manipulation task. Models with token-independent connectors (MLP projectors, linear projections without deep post-processing) degrade gracefully under pruning, while models with token-entangling connectors exhibit sharp, task-dependent collapse. Figure~\ref{fig:teaser} illustrates this two-axis structure.
17	
18	Table~\ref{tab:main_results} presents closed-loop success rates across four models, four LIBERO suites, two pruning methods, and four retention ratios. The data reveal four qualitatively distinct response patterns spanning the connector spectrum (Figure~\ref{fig:pruning_overview}).
19	
20	\textbf{$\pi_0.5$ (linear, CV$\,{=}\,$0.055).} On Object, L2 norm selection yields 98.2\% at $k{=}0.95$, 98.2\% at $k{=}0.9$, and 98.0\% at $k{=}0.85$ (a plateau within 0.2\,pp of the 98.2\% baseline), then drops sharply to 55.0\% at $k{=}0.7$. Random selection follows a different trajectory: 69.4\% at $k{=}0.95$, 12.0\% at $k{=}0.9$, 77.2\% at $k{=}0.7$, and 69.4\% at $k{=}0.5$. The low CV implies near-uniform token norms, and the method choice produces gaps as large as 86.2\,pp (at $k{=}0.9$). On Spatial, $\pi_0.5$ maintains 97.8\% at $k{=}0.95$ (L2) and degrades to 55.6\% at $k{=}0.5$ (L2) versus 71.6\% (random). The pattern is consistent: low-CV models are not pruning-immune but uniformly critical, where the choice of which tokens to remove matters more than the number removed.
21	
22	\textbf{X-VLA (linear + BART encoder, CV$\,{=}\,$0.151).} X-VLA exhibits threshold-graded behavior with a pronounced interaction between retention ratio and task complexity. On Object, L2 norm selection preserves 99.0\% at $k{=}0.95$ and 99.2\% at $k{=}0.9$ (matching the baseline), then falls sharply to 68.0\% at $k{=}0.85$ with non-monotonic recovery to 89.0\% at $k{=}0.8$ before continued decline to 56.2\% at $k{=}0.7$. The same model at the same $k{=}0.9$ achieves only 70.2\% on Goal, a 29.0\,pp gap driven entirely by task complexity. On Long, removing just 3 of 50 tokens ($k{=}0.95$) collapses SR from 94.0\% to 47.0\%. The 12-layer BART encoder creates cross-token dependencies that amplify under compositional task demands.
23	
24	\textbf{OpenVLA (MLP, CV$\,{=}\,$0.215).} OpenVLA degrades smoothly across all retention ratios on Object: 70.6\% (L2) and 69.2\% (random) at $k{=}0.95$, 62.0\% and 63.4\% at $k{=}0.9$, 49.0\% and 48.5\% at $k{=}0.7$, 37.4\% and 35.7\% at $k{=}0.5$. The near-zero method gap (within 2\,pp at all retention ratios) reflects the MLP projector's per-patch independence: with a genuine importance gradient (CV$\,{=}\,$0.215), L2 norm ranking and random selection yield comparable spatial coverage. Degradation is proportional to the fraction removed, with no threshold effects.
25	
26	\textbf{SmolVLA (pixel-shuffle, CV$\,{=}\,$0.314).} SmolVLA collapses to 0.0\% SR at every retention ratio across all four suites and both pruning methods, including $k{=}0.95$ where only 6 of 128 tokens are removed. This catastrophic cliff is detailed in Section~\ref{sec:pixel_shuffle}.
27	
28	\begin{table*}[t]
29	\centering
30	\small
31	\caption{Closed-loop success rates (\%) on LIBERO under L2 norm (L2) and random (R) token pruning at four retention ratios. Best result per row in \textbf{bold}. SmolVLA collapses to 0.0\% across all conditions. ``--'' indicates data not yet collected.}
32	\label{tab:main_results}
33	\begin{tabular}{llccccc}
34	\toprule
35	Model & Suite & Baseline & $k{=}0.95$ (L2 / R) & $k{=}0.9$ (L2 / R) & $k{=}0.7$ (L2 / R) & $k{=}0.5$ (L2 / R) \\
36	\midrule
37	\multirow{4}{*}{$\pi_0.5$}
38	& Object  & \textbf{98.2} & 98.2 / 69.4 & \textbf{98.2} / 12.0 & 55.0 / 77.2 & 33.4 / 69.4 \\
39	& Spatial & \textbf{97.2} & \textbf{97.8} / 76.4 & 95.0 / 54.6 & 67.0 / 74.4 & 55.6 / 71.6 \\
40	& Goal    & \textbf{96.4} & 89.4 / 84.0 & 90.0 / -- & -- / 80.6 & 59.2 / 74.4 \\
41	& Long    & \textbf{91.6} & 86.8 / 61.2 & 81.0 / 31.8 & 60.0 / 64.6 & 50.2 / 50.2 \\
42	\midrule
43	\multirow{4}{*}{X-VLA}
44	& Object  & \textbf{99.2} & 99.0 / 98.8 & \textbf{99.2} / 97.8 & 56.2 / 65.2 & 42.6 / 70.6 \\
45	& Spatial & \textbf{91.6} & 71.6 / 70.2 & 78.8 / -- & 72.0 / -- & 58.8 / 71.4 \\
46	& Goal    & \textbf{98.0} & 53.8 / 54.0 & 70.2 / -- & 53.4 / -- & 61.0 / -- \\
47	& Long    & \textbf{94.0} & 47.0 / -- & 27.5 / -- & -- / -- & -- / -- \\
48	\midrule
49	OpenVLA & Object & \textbf{74.0} & 70.6 / 69.2 & 62.0 / 63.4 & 49.0 / 48.5 & 37.4 / 35.7 \\
50	\midrule
51	\multirow{4}{*}{SmolVLA}
52	& Object  & \textbf{59.2} & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 \\
53	& Spatial & \textbf{44.6} & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 \\
54	& Goal    & \textbf{60.8} & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 \\
55	& Long    & \textbf{36.6} & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 \\
56	\bottomrule
57	\end{tabular}
58	\end{table*}
59	
60	\subsection{Pixel-Shuffle Entanglement}
61	\label{sec:pixel_shuffle}
62	
63	SmolVLA's pixel-shuffle connector applies $4{\times}4$ spatial folding, concatenating 16 contiguous patches into the channel dimension of a single token. This operation creates irreversible cross-token spatial dependencies: each token encodes a $4{\times}4$ receptive field, and removing any token eliminates information from all 16 constituent patches with no redundancy in the remaining tokens.
64	
65	The consequence is catastrophic. SmolVLA collapses to 0.0\% SR at $k{=}0.95$ (removing 6 of 128 tokens, a 5\% reduction) across all four LIBERO suites (Object, Spatial, Goal, Long) and both pruning methods (L2 norm and random). We verified this result on two independent checkpoints: our LoRA fine-tuned reproduction (44.8\% SR baseline) and the official SmolVLA checkpoint (59.2\% SR baseline). Both exhibit identical collapse. The cliff is architectural, not a training artifact.
66	
67	The pixel-shuffle mechanism explains why the collapse is method-independent. Because all tokens carry spatially entangled information from non-overlapping $4{\times}4$ grids, no scoring function can identify ``dispensable'' tokens. L2 norm ranking and random selection fail equally because the problem is not which tokens are removed but that any removal breaks the spatial completeness the downstream LLM requires. In contrast, MLP projectors (OpenVLA) and linear projections ($\pi_0.5$) map patches independently. Each token retains per-patch spatial locality, so partial removal does not destroy information from unrelated spatial positions.
68	
69	\subsection{When Does Pruning Method Matter? CV as Sensitivity Indicator}
70	\label{sec:cv_sensitivity}
71	
72	Token importance CV (coefficient of variation of L2 norms) correlates with the retention ratio at which the choice of pruning method becomes critical. At mild pruning ($k{=}0.95$), a clear pattern emerges across the three closed-loop models with distinct CV values.
73	
74	For $\pi_0.5$ (CV$\,{=}\,$0.055), the method gap at $k{=}0.95$ is substantial: 98.2\% (L2) versus 69.4\% (random) on Object, a 28.8\,pp difference. On Spatial, the gap is 21.4\,pp (97.8\% vs.\ 76.4\%). The near-uniform token norms cause L2 norm ranking to exploit small spatial correlations rather than genuine importance differences, while random selection preserves the uniform spatial coverage these models depend on.
75	
76	For X-VLA (CV$\,{=}\,$0.151), the method gap at $k{=}0.95$ is minimal on Object (0.2\,pp; Table~\ref{tab:main_results}). Across three suites with available data, the method gap averages 0.6\,pp (range 0.2--1.4\,pp). The BART encoder produces tokens with a moderate importance gradient that both methods preserve at this mild pruning level.
77	
78	For OpenVLA (CV$\,{=}\,$0.215), the method gap at $k{=}0.95$ is 1.4\,pp on Object (70.6\% vs.\ 69.2\%). The MLP projector creates a clear importance hierarchy that renders both selection strategies nearly equivalent.
79	
80	The contrast is stark: $\pi_0.5$ exhibits a 28.8\,pp method gap where X-VLA and OpenVLA show gaps below 1.5\,pp. Low-CV models are an order of magnitude more sensitive to pruning method choice than higher-CV models at mild retention ratios. Figure~\ref{fig:method_gap} visualizes this relationship.
81	
82	At aggressive compression ($k{=}0.5$), the method-independence observed in moderate-CV models breaks down. On Object, the gap $\Delta$(R$-$L2) scales monotonically with CV: $\pi_0.5$ shows $+$36.0\,pp (random: 69.4\%, L2: 33.4\%), X-VLA shows $+$28.0\,pp (random: 70.6\%, L2: 42.6\%), and OpenVLA shows $-$1.7\,pp (random: 35.7\%, L2: 37.4\%). At 50\% retention, random selection outperforms L2 norm selection for both low-CV and moderate-CV models because random sampling preserves spatial diversity, while L2 norm ranking selects correlated high-norm tokens that cluster in similar image regions. Only OpenVLA, with CV above 0.2, produces a genuine importance gradient that L2 can exploit without spatial clustering artifacts.
83	
84	\subsection{Cross-Suite Task Complexity Effects}
85	\label{sec:cross_suite}
86	
87	LIBERO's four suites form a complexity gradient: Object and Spatial require single-step manipulation with explicit spatial cues, while Goal and Long demand multi-step planning, goal inference, or extended temporal coordination. This gradient interacts with pruning tolerance in a connector-dependent manner.
88	
89	$\pi_0.5$ shows moderate complexity amplification under L2 norm pruning at $k{=}0.95$: Object retains 98.2\% (matching the baseline), Spatial retains 97.8\% (within noise of the 97.2\% baseline), and Goal drops to 89.4\% ($-$7.0\,pp from 96.4\%). Simple tasks absorb mild pruning with negligible loss; compositional tasks expose measurable degradation even at 5\% token removal.
90	
91	X-VLA exhibits dramatic complexity amplification. At $k{=}0.9$ with L2 norm selection, Object retains the full 99.2\% baseline, while Goal drops to 70.2\% ($-$27.8\,pp). Object absorbs 10\% token removal with zero loss; the same pruning ratio on multi-step tasks produces near-catastrophic degradation, driven entirely by task complexity with the same model and pruning method. The effect is even more pronounced at $k{=}0.95$ on Long: removing just 3 of 50 tokens collapses SR from 94.0\% to 47.0\%, a 47.0\,pp loss, while Object at the same ratio loses only 0.2\,pp.
92	
93	Token-entangling connectors (X-VLA's BART encoder) amplify task complexity because compositional tasks require integrating information across spatial locations. When the BART encoder creates cross-token dependencies, removing even a few tokens disrupts the distributed representations that multi-step tasks rely on. Token-independent connectors ($\pi_0.5$'s linear projection, OpenVLA's MLP) show moderate complexity amplification because each token's contribution is self-contained: removing tokens reduces spatial coverage proportionally, and simple tasks tolerate the resulting gaps.
94	
95	\subsection{VTR Recovery}
96	\label{sec:vtr_recovery}
97	
98	Vision Token Re-encoder (VTR) addresses the catastrophic cliff through learned re-encoding rather than hard deletion. VTR inserts a lightweight cross-attention module ($\sim$22M parameters, approximately 5\% of SmolVLA) between the pixel-shuffle connector and the LLM backbone. $M$ learned queries attend over the full set of 128 source tokens and produce $M$ compressed output representations, where $M \in \{16, 32, 64, 96, 128\}$. The $M{=}128$ configuration serves as a passthrough control that re-encodes without compressing.
99	
100	Table~\ref{tab:vtr_results} reports VTR results on SmolVLA for LIBERO-Object (3 seeds, 500 episodes each). Cross-attention VTR recovers substantial performance where hard pruning yields 0.0\%: $M{=}16$ (87.5\% compression) achieves 56.9 $\pm$ 1.3\%, $M{=}32$ (75\%) achieves 60.1 $\pm$ 1.3\%, $M{=}64$ (50\%) achieves 62.0 $\pm$ 2.2\%, $M{=}96$ (25\%) achieves 54.5 $\pm$ 3.2\%, and $M{=}128$ (0\%, passthrough) achieves 58.0 $\pm$ 3.5\%. The SmolVLA-Base (LoRA fine-tuned) baseline without VTR is 44.8\%, and the official SmolVLA baseline is 59.2\%.
101	
102	\begin{table}[t]
103	\centering
104	\small
105	\caption{VTR re-encoding on SmolVLA (LIBERO-Object). Cross-attention and MLP adapter results report mean $\pm$ std over 3 seeds (500 episodes each). The M-curve is flat: $M{=}16$ (87.5\% compression) matches $M{=}128$ (passthrough) within 1.1\,pp. The baseline control (100K extra training, no compressor) confirms the gain is architectural. ``Compression'' = fraction of tokens removed.}
106	\label{tab:vtr_results}
107	\begin{tabular}{lccr}
108	\toprule
109	Configuration & $M$ & Compression & SR (\%) \\
110	\midrule
111	\textit{SmolVLA-Base (LoRA)} & 128 & 0\% & 44.8 \\
112	\textit{SmolVLA official} & 128 & 0\% & 59.2 \\
113	\textit{Baseline control (+100K steps)} & 128 & 0\% & 45.0 \\
114	\textit{Hard pruning (any $k$)} & -- & 5--50\% & 0.0 \\
115	\midrule
116	Cross-attn VTR & 16 & 87.5\% & 56.9 $\pm$ 1.3 \\
117	Cross-attn VTR & 32 & 75\% & 60.1 $\pm$ 1.3 \\
118	Cross-attn VTR & 64 & 50\% & \textbf{62.0 $\pm$ 2.2} \\
119	Cross-attn VTR & 96 & 25\% & 54.5 $\pm$ 3.2 \\
120	Cross-attn VTR & 128 & 0\% & 58.0 $\pm$ 3.5 \\
121	\midrule
122	MLP adapter ($\sim$22M) & 32 & 75\% & 63.4 $\pm$ 2.6 \\
123	\bottomrule
124	\end{tabular}
125	\end{table}
126	
127	The M-curve is notably flat: performance at $M{=}16$ (56.9\%) falls within 1.1\,pp of $M{=}128$ (58.0\%), and all five $M$ values cluster within a 7.5\,pp range. This flatness confirms that the operative factor is learned re-encoding of spatially entangled tokens, not the compression ratio itself. The VTR module transforms pixel-shuffle representations into a format the downstream LLM can process robustly, and this transformation is effective regardless of how many output tokens carry the result.
128	
129	A parameter-matched MLP adapter ($\sim$22M parameters) achieves 63.4 $\pm$ 2.6\% at $M{=}32$, comparable to cross-attention VTR ($p = 0.15$). This confirms that re-encoding itself, rather than the specific attention mechanism, is the key architectural intervention. The baseline control (100K additional training steps without the compressor module) achieves only 45.0\% SR, within 0.2\,pp of the 44.8\% baseline. The performance gain is therefore attributable to the VTR architecture, not to additional optimization.
130	
131	Cross-suite evaluation at $M{=}32$ confirms that VTR recovery generalizes beyond Object: Spatial achieves 53.2\% and Goal achieves 56.4\%, both recovered from 0.0\% under hard pruning. VTR provides a targeted remedy for pixel-shuffle entanglement. By breaking the spatial dependencies that make hard deletion catastrophic, VTR enables both re-encoding recovery and downstream token reduction for deployment efficiency.
132	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "e4ae4a1e-00f6-4242-b943-68d43888aadb",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/experiments.tex",
      "content": "\\section{Experiments}\n\\label{sec:experiments}\n\n\\subsection{Experimental Setup}\n\\label{sec:exp_setup}\n\nWe evaluate vision token pruning across six VLA models spanning three connector families on the LIBERO benchmark~\\cite{liu2023libero}. LIBERO provides four task suites of increasing complexity: Object (object manipulation), Spatial (spatial reasoning), Goal (goal-conditioned tasks), and Long (long-horizon multi-step tasks). Each suite contains 10 tasks evaluated over 50 episodes, yielding 500 episodes per condition.\n\nFour models are evaluated in closed-loop robotic control: $\\pi_0.5$~\\cite{black2025pi05} (4B parameters, linear projection with $\\times\\!\\sqrt{d}$ scaling, 768 tokens from three cameras, CV$\\,{=}\\,$0.055), X-VLA~\\cite{zheng2025xvla} (880M, linear projection followed by a 12-layer BART encoder~\\cite{lewis2020bart}, 50 tokens, CV$\\,{=}\\,$0.151), OpenVLA~\\cite{kim2024openvla} (7B, three-layer MLP projector, 256 tokens, CV$\\,{=}\\,$0.215), and SmolVLA~\\cite{shukor2025smolvla} (450M, pixel-shuffle $4{\\times}4$ folding, 128 tokens, CV$\\,{=}\\,$0.314). Two additional models are analyzed via offline metrics only: $\\pi_0$~\\cite{black2024pi0} (3.3B, linear projection, 256 tokens, CV$\\,{=}\\,$0.038) and OFT~\\cite{kim2025openoft} (7B, MLP projector, 512 tokens, CV$\\,{=}\\,$0.219). Table~\\ref{tab:model_properties} summarizes model properties and connector details.\n\nThe pruning protocol applies post-connector token pruning at retention ratios $k \\in \\{0.3, 0.5, 0.7, 0.85, 0.9, 0.95\\}$. Two strategies bracket the robustness range: \\textbf{L2 norm selection} ranks tokens by L2 norm and retains the top-$k$ fraction, providing an importance-based favorable test; \\textbf{random subsampling} selects tokens uniformly at random, providing a conservative lower bound. Both strategies physically remove tokens and re-index position IDs. All results report mean success rate (SR) over 500 episodes with Wilson 95\\% confidence intervals for single-seed conditions.\n\n\\subsection{Two-Axis Framework Overview}\n\\label{sec:two_axis}\n\nThe pruning response of a VLA model depends on two axes: the degree of token independence imposed by the vision connector, and the complexity of the downstream manipulation task. Models with token-independent connectors (MLP projectors, linear projections without deep post-processing) degrade gracefully under pruning, while models with token-entangling connectors exhibit sharp, task-dependent collapse. Figure~\\ref{fig:teaser} illustrates this two-axis structure.\n\nTable~\\ref{tab:main_results} presents closed-loop success rates across four models, four LIBERO suites, two pruning methods, and four retention ratios. The data reveal four qualitatively distinct response patterns spanning the connector spectrum (Figure~\\ref{fig:pruning_overview}).\n\n\\textbf{$\\pi_0.5$ (linear, CV$\\,{=}\\,$0.055).} On Object, L2 norm selection yields 98.2\\% at $k{=}0.95$, 98.2\\% at $k{=}0.9$, and 98.0\\% at $k{=}0.85$ (a plateau within 0.2\\,pp of the 98.2\\% baseline), then drops sharply to 55.0\\% at $k{=}0.7$. Random selection follows a different trajectory: 69.4\\% at $k{=}0.95$, 12.0\\% at $k{=}0.9$, 77.2\\% at $k{=}0.7$, and 69.4\\% at $k{=}0.5$. The low CV implies near-uniform token norms, and the method choice produces gaps as large as 86.2\\,pp (at $k{=}0.9$). On Spatial, $\\pi_0.5$ maintains 97.8\\% at $k{=}0.95$ (L2) and degrades to 55.6\\% at $k{=}0.5$ (L2) versus 71.6\\% (random). The pattern is consistent: low-CV models are not pruning-immune but uniformly critical, where the choice of which tokens to remove matters more than the number removed.\n\n\\textbf{X-VLA (linear + BART encoder, CV$\\,{=}\\,$0.151).} X-VLA exhibits threshold-graded behavior with a pronounced interaction between retention ratio and task complexity. On Object, L2 norm selection preserves 99.0\\% at $k{=}0.95$ and 99.2\\% at $k{=}0.9$ (matching the baseline), then falls sharply to 68.0\\% at $k{=}0.85$ with non-monotonic recovery to 89.0\\% at $k{=}0.8$ before continued decline to 56.2\\% at $k{=}0.7$. The same model at the same $k{=}0.9$ achieves only 70.2\\% on Goal, a 29.0\\,pp gap driven entirely by task complexity. On Long, removing just 3 of 50 tokens ($k{=}0.95$) collapses SR from 94.0\\% to 47.0\\%. The 12-layer BART encoder creates cross-token dependencies that amplify under compositional task demands.\n\n\\textbf{OpenVLA (MLP, CV$\\,{=}\\,$0.215).} OpenVLA degrades smoothly across all retention ratios on Object: 70.6\\% (L2) and 69.2\\% (random) at $k{=}0.95$, 62.0\\% and 63.4\\% at $k{=}0.9$, 49.0\\% and 48.5\\% at $k{=}0.7$, 37.4\\% and 35.7\\% at $k{=}0.5$. The near-zero method gap (within 2\\,pp at all retention ratios) reflects the MLP projector's per-patch independence: with a genuine importance gradient (CV$\\,{=}\\,$0.215), L2 norm ranking and random selection yield comparable spatial coverage. Degradation is proportional to the fraction removed, with no threshold effects.\n\n\\textbf{SmolVLA (pixel-shuffle, CV$\\,{=}\\,$0.314).} SmolVLA collapses to 0.0\\% SR at every retention ratio across all four suites and both pruning methods, including $k{=}0.95$ where only 6 of 128 tokens are removed. This catastrophic cliff is detailed in Section~\\ref{sec:pixel_shuffle}.\n\n\\begin{table*}[t]\n\\centering\n\\small\n\\caption{Closed-loop success rates (\\%) on LIBERO under L2 norm (L2) and random (R) token pruning at four retention ratios. Best result per row in \\textbf{bold}. SmolVLA collapses to 0.0\\% across all conditions. ``--'' indicates data not yet collected.}\n\\label{tab:main_results}\n\\begin{tabular}{llccccc}\n\\toprule\nModel & Suite & Baseline & $k{=}0.95$ (L2 / R) & $k{=}0.9$ (L2 / R) & $k{=}0.7$ (L2 / R) & $k{=}0.5$ (L2 / R) \\\\\n\\midrule\n\\multirow{4}{*}{$\\pi_0.5$}\n& Object  & \\textbf{98.2} & 98.2 / 69.4 & \\textbf{98.2} / 12.0 & 55.0 / 77.2 & 33.4 / 69.4 \\\\\n& Spatial & \\textbf{97.2} & \\textbf{97.8} / 76.4 & 95.0 / 54.6 & 67.0 / 74.4 & 55.6 / 71.6 \\\\\n& Goal    & \\textbf{96.4} & 89.4 / 84.0 & 90.0 / -- & -- / 80.6 & 59.2 / 74.4 \\\\\n& Long    & \\textbf{91.6} & 86.8 / 61.2 & 81.0 / 31.8 & 60.0 / 64.6 & 50.2 / 50.2 \\\\\n\\midrule\n\\multirow{4}{*}{X-VLA}\n& Object  & \\textbf{99.2} & 99.0 / 98.8 & \\textbf{99.2} / 97.8 & 56.2 / 65.2 & 42.6 / 70.6 \\\\\n& Spatial & \\textbf{91.6} & 71.6 / 70.2 & 78.8 / -- & 72.0 / -- & 58.8 / 71.4 \\\\\n& Goal    & \\textbf{98.0} & 53.8 / 54.0 & 70.2 / -- & 53.4 / -- & 61.0 / -- \\\\\n& Long    & \\textbf{94.0} & 47.0 / -- & 27.5 / -- & -- / -- & -- / -- \\\\\n\\midrule\nOpenVLA & Object & \\textbf{74.0} & 70.6 / 69.2 & 62.0 / 63.4 & 49.0 / 48.5 & 37.4 / 35.7 \\\\\n\\midrule\n\\multirow{4}{*}{SmolVLA}\n& Object  & \\textbf{59.2} & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 \\\\\n& Spatial & \\textbf{44.6} & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 \\\\\n& Goal    & \\textbf{60.8} & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 \\\\\n& Long    & \\textbf{36.6} & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 & 0.0 / 0.0 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table*}\n\n\\subsection{Pixel-Shuffle Entanglement}\n\\label{sec:pixel_shuffle}\n\nSmolVLA's pixel-shuffle connector applies $4{\\times}4$ spatial folding, concatenating 16 contiguous patches into the channel dimension of a single token. This operation creates irreversible cross-token spatial dependencies: each token encodes a $4{\\times}4$ receptive field, and removing any token eliminates information from all 16 constituent patches with no redundancy in the remaining tokens.\n\nThe consequence is catastrophic. SmolVLA collapses to 0.0\\% SR at $k{=}0.95$ (removing 6 of 128 tokens, a 5\\% reduction) across all four LIBERO suites (Object, Spatial, Goal, Long) and both pruning methods (L2 norm and random). We verified this result on two independent checkpoints: our LoRA fine-tuned reproduction (44.8\\% SR baseline) and the official SmolVLA checkpoint (59.2\\% SR baseline). Both exhibit identical collapse. The cliff is architectural, not a training artifact.\n\nThe pixel-shuffle mechanism explains why the collapse is method-independent. Because all tokens carry spatially entangled information from non-overlapping $4{\\times}4$ grids, no scoring function can identify ``dispensable'' tokens. L2 norm ranking and random selection fail equally because the problem is not which tokens are removed but that any removal breaks the spatial completeness the downstream LLM requires. In contrast, MLP projectors (OpenVLA) and linear projections ($\\pi_0.5$) map patches independently. Each token retains per-patch spatial locality, so partial removal does not destroy information from unrelated spatial positions.\n\n\\subsection{When Does Pruning Method Matter? CV as Sensitivity Indicator}\n\\label{sec:cv_sensitivity}\n\nToken importance CV (coefficient of variation of L2 norms) correlates with the retention ratio at which the choice of pruning method becomes critical. At mild pruning ($k{=}0.95$), a clear pattern emerges across the three closed-loop models with distinct CV values.\n\nFor $\\pi_0.5$ (CV$\\,{=}\\,$0.055), the method gap at $k{=}0.95$ is substantial: 98.2\\% (L2) versus 69.4\\% (random) on Object, a 28.8\\,pp difference. On Spatial, the gap is 21.4\\,pp (97.8\\% vs.\\ 76.4\\%). The near-uniform token norms cause L2 norm ranking to exploit small spatial correlations rather than genuine importance differences, while random selection preserves the uniform spatial coverage these models depend on.\n\nFor X-VLA (CV$\\,{=}\\,$0.151), the method gap at $k{=}0.95$ is minimal on Object (0.2\\,pp; Table~\\ref{tab:main_results}). Across three suites with available data, the method gap averages 0.6\\,pp (range 0.2--1.4\\,pp). The BART encoder produces tokens with a moderate importance gradient that both methods preserve at this mild pruning level.\n\nFor OpenVLA (CV$\\,{=}\\,$0.215), the method gap at $k{=}0.95$ is 1.4\\,pp on Object (70.6\\% vs.\\ 69.2\\%). The MLP projector creates a clear importance hierarchy that renders both selection strategies nearly equivalent.\n\nThe contrast is stark: $\\pi_0.5$ exhibits a 28.8\\,pp method gap where X-VLA and OpenVLA show gaps below 1.5\\,pp. Low-CV models are an order of magnitude more sensitive to pruning method choice than higher-CV models at mild retention ratios. Figure~\\ref{fig:method_gap} visualizes this relationship.\n\nAt aggressive compression ($k{=}0.5$), the method-independence observed in moderate-CV models breaks down. On Object, the gap $\\Delta$(R$-$L2) scales monotonically with CV: $\\pi_0.5$ shows $+$36.0\\,pp (random: 69.4\\%, L2: 33.4\\%), X-VLA shows $+$28.0\\,pp (random: 70.6\\%, L2: 42.6\\%), and OpenVLA shows $-$1.7\\,pp (random: 35.7\\%, L2: 37.4\\%). At 50\\% retention, random selection outperforms L2 norm selection for both low-CV and moderate-CV models because random sampling preserves spatial diversity, while L2 norm ranking selects correlated high-norm tokens that cluster in similar image regions. Only OpenVLA, with CV above 0.2, produces a genuine importance gradient that L2 can exploit without spatial clustering artifacts.\n\n\\subsection{Cross-Suite Task Complexity Effects}\n\\label{sec:cross_suite}\n\nLIBERO's four suites form a complexity gradient: Object and Spatial require single-step manipulation with explicit spatial cues, while Goal and Long demand multi-step planning, goal inference, or extended temporal coordination. This gradient interacts with pruning tolerance in a connector-dependent manner.\n\n$\\pi_0.5$ shows moderate complexity amplification under L2 norm pruning at $k{=}0.95$: Object retains 98.2\\% (matching the baseline), Spatial retains 97.8\\% (within noise of the 97.2\\% baseline), and Goal drops to 89.4\\% ($-$7.0\\,pp from 96.4\\%). Simple tasks absorb mild pruning with negligible loss; compositional tasks expose measurable degradation even at 5\\% token removal.\n\nX-VLA exhibits dramatic complexity amplification. At $k{=}0.9$ with L2 norm selection, Object retains the full 99.2\\% baseline, while Goal drops to 70.2\\% ($-$27.8\\,pp). Object absorbs 10\\% token removal with zero loss; the same pruning ratio on multi-step tasks produces near-catastrophic degradation, driven entirely by task complexity with the same model and pruning method. The effect is even more pronounced at $k{=}0.95$ on Long: removing just 3 of 50 tokens collapses SR from 94.0\\% to 47.0\\%, a 47.0\\,pp loss, while Object at the same ratio loses only 0.2\\,pp.\n\nToken-entangling connectors (X-VLA's BART encoder) amplify task complexity because compositional tasks require integrating information across spatial locations. When the BART encoder creates cross-token dependencies, removing even a few tokens disrupts the distributed representations that multi-step tasks rely on. Token-independent connectors ($\\pi_0.5$'s linear projection, OpenVLA's MLP) show moderate complexity amplification because each token's contribution is self-contained: removing tokens reduces spatial coverage proportionally, and simple tasks tolerate the resulting gaps.\n\n\\subsection{VTR Recovery}\n\\label{sec:vtr_recovery}\n\nVision Token Re-encoder (VTR) addresses the catastrophic cliff through learned re-encoding rather than hard deletion. VTR inserts a lightweight cross-attention module ($\\sim$22M parameters, approximately 5\\% of SmolVLA) between the pixel-shuffle connector and the LLM backbone. $M$ learned queries attend over the full set of 128 source tokens and produce $M$ compressed output representations, where $M \\in \\{16, 32, 64, 96, 128\\}$. The $M{=}128$ configuration serves as a passthrough control that re-encodes without compressing.\n\nTable~\\ref{tab:vtr_results} reports VTR results on SmolVLA for LIBERO-Object (3 seeds, 500 episodes each). Cross-attention VTR recovers substantial performance where hard pruning yields 0.0\\%: $M{=}16$ (87.5\\% compression) achieves 56.9 $\\pm$ 1.3\\%, $M{=}32$ (75\\%) achieves 60.1 $\\pm$ 1.3\\%, $M{=}64$ (50\\%) achieves 62.0 $\\pm$ 2.2\\%, $M{=}96$ (25\\%) achieves 54.5 $\\pm$ 3.2\\%, and $M{=}128$ (0\\%, passthrough) achieves 58.0 $\\pm$ 3.5\\%. The SmolVLA-Base (LoRA fine-tuned) baseline without VTR is 44.8\\%, and the official SmolVLA baseline is 59.2\\%.\n\n\\begin{table}[t]\n\\centering\n\\small\n\\caption{VTR re-encoding on SmolVLA (LIBERO-Object). Cross-attention and MLP adapter results report mean $\\pm$ std over 3 seeds (500 episodes each). The M-curve is flat: $M{=}16$ (87.5\\% compression) matches $M{=}128$ (passthrough) within 1.1\\,pp. The baseline control (100K extra training, no compressor) confirms the gain is architectural. ``Compression'' = fraction of tokens removed.}\n\\label{tab:vtr_results}\n\\begin{tabular}{lccr}\n\\toprule\nConfiguration & $M$ & Compression & SR (\\%) \\\\\n\\midrule\n\\textit{SmolVLA-Base (LoRA)} & 128 & 0\\% & 44.8 \\\\\n\\textit{SmolVLA official} & 128 & 0\\% & 59.2 \\\\\n\\textit{Baseline control (+100K steps)} & 128 & 0\\% & 45.0 \\\\\n\\textit{Hard pruning (any $k$)} & -- & 5--50\\% & 0.0 \\\\\n\\midrule\nCross-attn VTR & 16 & 87.5\\% & 56.9 $\\pm$ 1.3 \\\\\nCross-attn VTR & 32 & 75\\% & 60.1 $\\pm$ 1.3 \\\\\nCross-attn VTR & 64 & 50\\% & \\textbf{62.0 $\\pm$ 2.2} \\\\\nCross-attn VTR & 96 & 25\\% & 54.5 $\\pm$ 3.2 \\\\\nCross-attn VTR & 128 & 0\\% & 58.0 $\\pm$ 3.5 \\\\\n\\midrule\nMLP adapter ($\\sim$22M) & 32 & 75\\% & 63.4 $\\pm$ 2.6 \\\\\n\\bottomrule\n\\end{tabular}\n\\end{table}\n\nThe M-curve is notably flat: performance at $M{=}16$ (56.9\\%) falls within 1.1\\,pp of $M{=}128$ (58.0\\%), and all five $M$ values cluster within a 7.5\\,pp range. This flatness confirms that the operative factor is learned re-encoding of spatially entangled tokens, not the compression ratio itself. The VTR module transforms pixel-shuffle representations into a format the downstream LLM can process robustly, and this transformation is effective regardless of how many output tokens carry the result.\n\nA parameter-matched MLP adapter ($\\sim$22M parameters) achieves 63.4 $\\pm$ 2.6\\% at $M{=}32$, comparable to cross-attention VTR ($p = 0.15$). This confirms that re-encoding itself, rather than the specific attention mechanism, is the key architectural intervention. The baseline control (100K additional training steps without the compressor module) achieves only 45.0\\% SR, within 0.2\\,pp of the 44.8\\% baseline. The performance gain is therefore attributable to the VTR architecture, not to additional optimization.\n\nCross-suite evaluation at $M{=}32$ confirms that VTR recovery generalizes beyond Object: Spatial achieves 53.2\\% and Goal achieves 56.4\\%, both recovered from 0.0\\% under hard pruning. VTR provides a targeted remedy for pixel-shuffle entanglement. By breaking the spatial dependencies that make hard deletion catastrophic, VTR enables both re-encoding recovery and downstream token reduction for deployment efficiency.\n",
      "numLines": 132,
      "startLine": 1,
      "totalLines": 132
    }
  }
}
```

</details>

---

### Assistant

_source line 15_

<details><summary>Logged reasoning block</summary>

```text
Now I have a thorough understanding of the paper's content, key findings, and numbers. Let me draft the abstract following all constraints:

Key constraints:
- ~200 words (CoRL 2026)
- `\begin{abstract}...\end{abstract}`
- No `\section` or `\label`
- No `\cite{}`
- No em-dashes (—)
- No delve/leverage/utilize/facilitate/significantly
- No "This paper presents..." / "We present..." / "In this work..." opening
- Use "analysis" not "framework"
- CV = "correlates with", not "predicts/determines"


- Start with concrete finding, not generic opener

I'm now organizing the key empirical results to weave into the abstract: SmolVLA drops from 59.2% to 0.0% at high compression, while π0.5 maintains 98.2% at k=0.95 on Object tasks with L2 distance, and X-VLA shows 99.2% on Object at k=0.9 but suffers a 27.8 percentage point decline on Goal tasks at the same compression level. The method exhibits a 15× sensitivity ratio across different VLAs, VTR stays above 60% even at 75% compression, and the correlation values range from 0.038 to 0.314 across the six VLA models tested. Vision token pruning reduces VLA computation by 50% or more in image classification, but its effectiveness in Vision-Language-Action models varies dramatically—removing just 5% of tokens can collapse SmolVLA from 59.2% to 0.0% success rate, while π_0.5 retains 98.2%. The vision connector architecture is the critical factor determining whether pruning succeeds or fails. I'm analyzing token compressibility across two dimensions: how tightly the connector couples tokens together versus whether it operates independently, and how task complexity escalates from single-step to multi-step manipulation. Token-entangling connectors show task-amplified collapse—X-VLA maintains 99.2% baseline performance on simple object manipulation at 90% retention but drops 27.8 percentage points on multi-step goal tasks at the same ratio, while SmolVLA's pixel-shuffle connector exhibits similar patterns.

The coefficient of variation in post-connector token norms correlates strongly with pruning robustness and method sensitivity: low-CV models are 15 times more sensitive to which pruning method you choose than higher-CV models, and at aggressive compression, random selection actually outperforms L2 norm ranking by 36 percentage points for these architectures. For pixel-shuffle connectors where all standard pruning fails, Vision Token Re-encoder recovers over 60% success rate at 75% compression through learned re-encoding. The evaluation covers six VLA models ranging from 450M to 7B parameters across three connector families and four task suites.

Now I'm refocusing on the core narrative for the conference version—the key insight is that token-entangling connectors amplify task complexity effects, where performance collapses differently depending on whether you're doing single-step or multi-step manipulation tasks.

The coefficient of variation in post-connector token norms is the critical predictor: low-CV models are far more sensitive to which pruning method you choose, and when compression gets aggressive, random selection actually beats principled L2 norm ranking for these architectures. For the worst-case pixel-shuffle connectors where everything fails, Vision Token Re-encoder recovers performance through learned re-encoding at high compression ratios. The evaluation covers six different VLAs across multiple connector families and task suites.

Now I'm seeing that token pruning's impact on VLAs is wildly inconsistent—removing just 5% of tokens can completely break some models while others barely notice, and the vision connector is what determines whether you get near-lossless compression or catastrophic failure. I'm analyzing this along two dimensions: how tightly coupled the connector is to individual tokens versus how it entangles them together, and whether the task requires single-step or multi-step reasoning. Token-entangling connectors show task-dependent collapse patterns, where X-VLA maintains its baseline performance on simpler tasks but degrades on more complex ones.

The variation in how tightly packed the token embeddings are after the connector—measured by coefficient of variation—directly predicts both how much pruning a model can tolerate and how sensitive it is to which pruning method you choose. Models with low variation are dramatically more sensitive to the pruning strategy, and at extreme compression levels, random token selection actually outperforms careful L2 norm-based ranking for these architectures. For pixel-shuffle connectors where everything fails completely, I'm exploring whether a lightweight re-encoding module using cross-attention can recover performance by learning to reconstruct the pruned information.

The evaluation covers six different vision-language action models ranging from 450 million to 7 billion parameters, three different connector designs, and four task suites from LIBERO. Checking the phrasing now — I don't have any explanatory en-dashes either, and my opening "Token pruning reduces..." avoids the forbidden patterns like "This paper presents" or "We present". The two-axis analysis framing is correct, and I'm not using any -ing phrase endings to wrap up sentences. I'm verifying that all abbreviations are properly defined in the abstract—VLA, CV, and VTR all check out. I don't use the ViT abbreviation anywhere so that doesn't need defining. For the LaTeX notation, I'm matching the convention used consistently throughout the experiments where $\pi_0.5$ appears without braces, even though it renders slightly unconventionally.

Now I'm sharpening the problem statement to be more compelling. Instead of a generic opening about token pruning reducing computation, I want to lead with the dramatic contrast: removing just 5% of tokens completely breaks SmolVLA's performance while the same reduction barely affects $\pi_0.5$. This sets up the core mystery—that the vision connector is the critical variable determining whether pruning helps or hurts. I'm crafting a problem statement that captures both the promise of token pruning in standard vision tasks and the surprising fragility in VLA systems, all within the ~30 word target. I'm drafting a more concise abstract that leads with the dramatic finding about token pruning's unpredictable effects across different VLA architectures, then systematically analyzing how the vision connector's design—whether it entangles tokens or keeps them independent—determines both pruning robustness and sensitivity to compression method, with the coefficient of variation in post-connector token norms serving as a diagnostic metric that predicts failure modes across six models and multiple task suites. I'm drafting the abstract with concrete findings upfront—showing how token pruning fails catastrophically on SmolVLA but succeeds on π_0.5, then explaining that the vision connector architecture is the key variable determining pruning robustness. I'm structuring the rest around two diagnostic axes: connector coupling and task complexity, using the coefficient of variation as a single metric that predicts both pruning tolerance and method sensitivity. The abstract covers how token-entangling connectors amplify failures on complex tasks, how low-CV models are far more sensitive to pruning method choice, and how Vision Token Re-encoder recovers performance on otherwise-failing pixel-shuffle connectors, all evaluated across six models and multiple task suites. Low-CV models show 15× greater sensitivity to pruning method choice, and at aggressive compression levels, random selection surprisingly outperforms L2 norm ranking by 36 percentage points for these architectures. Pixel-shuffle connectors present a different challenge where all pruning strategies fail completely, but Vision Token Re-encoder recovers over 60% success rate at 75% compression through learned re-encoding. The evaluation spans six VLAs ranging from 450M to 7B parameters across three connector families and four LIBERO task suites. Checking the coefficient of variation range from 0.038 to 0.314, and confirming the model scope covers six VLAs ranging from 450M to 7B parameters. Also verifying that the 5% token removal at k=0.95 correctly produces the SmolVLA collapse from 59.2% to 0.0%, and double-checking the 36 percentage point gap between random and L2 pruning at aggressive compression levels. I need to verify the LaTeX notation for the model name—whether `$\pi_0.5$` or `$\pi_{0.5}$` is correct based on how it appears in the paper and citations.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "b3d18f53-a3bc-4cbb-8cbe-6d78637a14d0",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ppn4jgrXFLPUULSvHAyfv4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19283,
      "cache_read_input_tokens": 24443,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19283
      },
      "output_tokens": 10,
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

Reading the skill files and reference papers to ensure consistency.

Now let me check if the output directory exists.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "5579ea05-9a1d-422a-a37f-e396cb3875ba",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ppn4jgrXFLPUULSvHAyfv4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19283,
      "cache_read_input_tokens": 24443,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19283
      },
      "output_tokens": 10,
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

<details open><summary>🔧 Tool call — Bash · `toolu_014DW7dspjwBA8qBBXSAx1wn`</summary>

```json
{
  "command": "ls /home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/",
  "description": "List paper directory"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "489b3bdd-3ccc-4f1a-aec8-aa55e3c5ff42",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Ppn4jgrXFLPUULSvHAyfv4",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 19283,
      "cache_read_input_tokens": 24443,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 19283
      },
      "output_tokens": 10,
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

_source line 18 · 2026-05-23T02:07:54.739Z_

<details><summary>↩ Tool result · `toolu_014DW7dspjwBA8qBBXSAx1wn`</summary>

```text
_pdf_images
abstract.tex
analysis.tex
appendix.tex
background.tex
conclusion.tex
corl_2026.sty
corlabbrvnat.bst
discussion.tex
experimental_setup.tex
experiments.tex
experiments_deprecated.tex
figures
introduction.tex
main.aux
main.bbl
main.blg
main.fdb_latexmk
main.fls
main.log
main.out
main.pdf
main.tex
method.tex
notes
references.bib
references.bib.prev
related_work.tex
results.tex
results_v2.tex
sections
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "a0d0c2ee-f5c1-47fa-857d-838c03d6b2ba",
  "tool_use_result": {
    "stdout": "_pdf_images\nabstract.tex\nanalysis.tex\nappendix.tex\nbackground.tex\nconclusion.tex\ncorl_2026.sty\ncorlabbrvnat.bst\ndiscussion.tex\nexperimental_setup.tex\nexperiments.tex\nexperiments_deprecated.tex\nfigures\nintroduction.tex\nmain.aux\nmain.bbl\nmain.blg\nmain.fdb_latexmk\nmain.fls\nmain.log\nmain.out\nmain.pdf\nmain.tex\nmethod.tex\nnotes\nreferences.bib\nreferences.bib.prev\nrelated_work.tex\nresults.tex\nresults_v2.tex\nsections",
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

_source line 19_

<details open><summary>🔧 Tool call — Read · `toolu_01GSGkJpPJrGchnUhsDCi6g1`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/abstract.tex"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "9ca7e33a-8d04-4c82-a1a9-87bbbadc0c77",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01CuwfjPXorTGka46BSmTz46",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 7448,
      "cache_read_input_tokens": 43726,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 7448
      },
      "output_tokens": 65,
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

_source line 20 · 2026-05-23T02:08:07.981Z_

<details><summary>↩ Tool result · `toolu_01GSGkJpPJrGchnUhsDCi6g1`</summary>

```text
1	\begin{abstract}
2	Vision token pruning accelerates Vision Transformer inference with negligible accuracy loss, but whether this robustness transfers to Vision-Language-Action (VLA) models remains untested across architectures. We study seven VLA models (450M--7B parameters) spanning three vision connector families, evaluating four in closed-loop robotic manipulation (LIBERO) and analyzing three via offline metrics or literature. The vision connector is strongly associated with pruning behavior along a four-class compressibility spectrum. Uniformly critical models ($\pi_0$, $\pi_0.5$; CV $< 0.06$) tolerate random subsampling but collapse under importance-based selection: $\pi_0.5$ retains 69.4\% success rate with random removal at 50\% retention but drops to 33.4\% under L2 norm selection, a 36 percentage-point gap demonstrating that offline pruning tolerance does not guarantee closed-loop robustness. Threshold-graded models (X-VLA; CV $= 0.151$) maintain $97.8 \pm 0.4$\% through 90\% retention before cliffing at 85\% ($-$31\,pp). Smooth graded models (OpenVLA, OFT; CV $\approx 0.22$) degrade proportionally. Catastrophic cliff models (SmolVLA; CV $= 0.314$) collapse to 0\% at 5\% removal across all seven tested configurations. The coefficient of variation (CV) of token L2 norms serves as a zero-cost diagnostic metric that correlates with both the tolerance class and the optimal pruning strategy from a single forward pass. The gap between random and L2 norm selection scales monotonically with CV at both 50\% and 70\% retention across three models. For catastrophic-cliff architectures, Vision Token Re-encoder (VTR) recovers 60\%+ success rate at 75\% compression where all deletion methods yield 0\%, with a relatively stable M-curve ($M{=}16 \approx M{=}128$) confirming learned re-encoding as the key factor. CV diagnosis followed by connector-appropriate compression forms a diagnostic protocol for safe VLA token reduction.
3	\end{abstract}
4	
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "3edce130-ba1a-4d7c-be27-bda4e047fdf8",
  "tool_use_result": {
    "type": "text",
    "file": {
      "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/abstract.tex",
      "content": "\\begin{abstract}\nVision token pruning accelerates Vision Transformer inference with negligible accuracy loss, but whether this robustness transfers to Vision-Language-Action (VLA) models remains untested across architectures. We study seven VLA models (450M--7B parameters) spanning three vision connector families, evaluating four in closed-loop robotic manipulation (LIBERO) and analyzing three via offline metrics or literature. The vision connector is strongly associated with pruning behavior along a four-class compressibility spectrum. Uniformly critical models ($\\pi_0$, $\\pi_0.5$; CV $< 0.06$) tolerate random subsampling but collapse under importance-based selection: $\\pi_0.5$ retains 69.4\\% success rate with random removal at 50\\% retention but drops to 33.4\\% under L2 norm selection, a 36 percentage-point gap demonstrating that offline pruning tolerance does not guarantee closed-loop robustness. Threshold-graded models (X-VLA; CV $= 0.151$) maintain $97.8 \\pm 0.4$\\% through 90\\% retention before cliffing at 85\\% ($-$31\\,pp). Smooth graded models (OpenVLA, OFT; CV $\\approx 0.22$) degrade proportionally. Catastrophic cliff models (SmolVLA; CV $= 0.314$) collapse to 0\\% at 5\\% removal across all seven tested configurations. The coefficient of variation (CV) of token L2 norms serves as a zero-cost diagnostic metric that correlates with both the tolerance class and the optimal pruning strategy from a single forward pass. The gap between random and L2 norm selection scales monotonically with CV at both 50\\% and 70\\% retention across three models. For catastrophic-cliff architectures, Vision Token Re-encoder (VTR) recovers 60\\%+ success rate at 75\\% compression where all deletion methods yield 0\\%, with a relatively stable M-curve ($M{=}16 \\approx M{=}128$) confirming learned re-encoding as the key factor. CV diagnosis followed by connector-appropriate compression forms a diagnostic protocol for safe VLA token reduction.\n\\end{abstract}\n",
      "numLines": 4,
      "startLine": 1,
      "totalLines": 4
    }
  }
}
```

</details>

---

### Assistant

_source line 21_

<details><summary>Logged reasoning block</summary>

```text
OK, there's an existing abstract. I need to rewrite it to match the updated specifications. The existing abstract has several issues:
1. Says "seven VLA models" but should be "six"
2. Uses en-dashes (--) 
3. Doesn't follow the Problem → Framework → Key Findings → Scale structure well
4. Doesn't lead with a concrete finding
5. Too long (~250 words)
6. Some numbers don't match the requirements

Let me write the new version.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "56dd756d-599b-464a-bd5e-ef7cbe68a7aa",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Njqy4VcPbB4UkNDSCqjXSb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 639,
      "cache_read_input_tokens": 51174,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 639
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

_source line 22_

Existing abstract is outdated (says "seven" models, uses en-dashes, wrong structure). Writing the updated version.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "7054518a-5b3f-4b26-b318-6ee1f41f2d4f",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Njqy4VcPbB4UkNDSCqjXSb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 639,
      "cache_read_input_tokens": 51174,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 639
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

_source line 23_

<details open><summary>🔧 Tool call — Write · `toolu_01D4dtnmLEVNcEWTdReAJGfx`</summary>

```json
{
  "file_path": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/abstract.tex",
  "content": "\\begin{abstract}\nRemoving 5\\% of vision tokens collapses SmolVLA from 59.2\\% to 0.0\\% success rate, while the same reduction on $\\pi_0.5$ retains 98.2\\%. Token pruning, well-established for Vision Transformers, transfers unpredictably across Vision-Language-Action (VLA) models because the vision connector governs token compressibility. We analyze this sensitivity along two axes: connector coupling (token-independent vs.\\ token-entangling) and task complexity (single-step vs.\\ multi-step manipulation). The coefficient of variation (CV) of post-connector token L2 norms, ranging from 0.038 to 0.314 across models, serves as a single-pass diagnostic that correlates with both pruning tolerance and method sensitivity. Token-entangling connectors exhibit task-amplified collapse: X-VLA retains its full 99.2\\% baseline on single-step Object manipulation at 90\\% retention but loses 27.8 percentage points on multi-step Goal tasks at the same ratio. Low-CV models show 15$\\times$ greater sensitivity to pruning method choice than higher-CV models, and at aggressive compression random selection outperforms L2 norm ranking by 36 percentage points for low-CV architectures. For pixel-shuffle connectors where all pruning strategies yield 0.0\\%, Vision Token Re-encoder (VTR), a lightweight cross-attention module, recovers over 60\\% success rate at 75\\% compression through learned re-encoding. Evaluation spans six VLAs (450M to 7B parameters), three connector families, and four LIBERO task suites.\n\\end{abstract}\n"
}
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "f754fd07-117d-4e88-899b-06160cab5564",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_01Njqy4VcPbB4UkNDSCqjXSb",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 639,
      "cache_read_input_tokens": 51174,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 639
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

_source line 24 · 2026-05-23T02:08:24.844Z_

<details><summary>↩ Tool result · `toolu_01D4dtnmLEVNcEWTdReAJGfx`</summary>

```text
The file /home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/abstract.tex has been updated successfully.
```

</details>

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "user",
  "type": "user",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "146ed4df-1f5a-4510-adae-2e4ea94e0370",
  "tool_use_result": {
    "type": "update",
    "filePath": "/home/ubuntu/.agent-ml-research-be-idea-gen-0515-2/projects/importance_margin_vla_compress/docs/paper/abstract.tex",
    "content": "\\begin{abstract}\nRemoving 5\\% of vision tokens collapses SmolVLA from 59.2\\% to 0.0\\% success rate, while the same reduction on $\\pi_0.5$ retains 98.2\\%. Token pruning, well-established for Vision Transformers, transfers unpredictably across Vision-Language-Action (VLA) models because the vision connector governs token compressibility. We analyze this sensitivity along two axes: connector coupling (token-independent vs.\\ token-entangling) and task complexity (single-step vs.\\ multi-step manipulation). The coefficient of variation (CV) of post-connector token L2 norms, ranging from 0.038 to 0.314 across models, serves as a single-pass diagnostic that correlates with both pruning tolerance and method sensitivity. Token-entangling connectors exhibit task-amplified collapse: X-VLA retains its full 99.2\\% baseline on single-step Object manipulation at 90\\% retention but loses 27.8 percentage points on multi-step Goal tasks at the same ratio. Low-CV models show 15$\\times$ greater sensitivity to pruning method choice than higher-CV models, and at aggressive compression random selection outperforms L2 norm ranking by 36 percentage points for low-CV architectures. For pixel-shuffle connectors where all pruning strategies yield 0.0\\%, Vision Token Re-encoder (VTR), a lightweight cross-attention module, recovers over 60\\% success rate at 75\\% compression through learned re-encoding. Evaluation spans six VLAs (450M to 7B parameters), three connector families, and four LIBERO task suites.\n\\end{abstract}\n",
    "structuredPatch": [
      {
        "oldStart": 1,
        "oldLines": 3,
        "newStart": 1,
        "newLines": 3,
        "lines": [
          " \\begin{abstract}",
          "-Vision token pruning accelerates Vision Transformer inference with negligible accuracy loss, but whether this robustness transfers to Vision-Language-Action (VLA) models remains untested across architectures. We study seven VLA models (450M--7B parameters) spanning three vision connector families, evaluating four in closed-loop robotic manipulation (LIBERO) and analyzing three via offline metrics or literature. The vision connector is strongly associated with pruning behavior along a four-class compressibility spectrum. Uniformly critical models ($\\pi_0$, $\\pi_0.5$; CV $< 0.06$) tolerate random subsampling but collapse under importance-based selection: $\\pi_0.5$ retains 69.4\\% success rate with random removal at 50\\% retention but drops to 33.4\\% under L2 norm selection, a 36 percentage-point gap demonstrating that offline pruning tolerance does not guarantee closed-loop robustness. Threshold-graded models (X-VLA; CV $= 0.151$) maintain $97.8 \\pm 0.4$\\% through 90\\% retention before cliffing at 85\\% ($-$31\\,pp). Smooth graded models (OpenVLA, OFT; CV $\\approx 0.22$) degrade proportionally. Catastrophic cliff models (SmolVLA; CV $= 0.314$) collapse to 0\\% at 5\\% removal across all seven tested configurations. The coefficient of variation (CV) of token L2 norms serves as a zero-cost diagnostic metric that correlates with both the tolerance class and the optimal pruning strategy from a single forward pass. The gap between random and L2 norm selection scales monotonically with CV at both 50\\% and 70\\% retention across three models. For catastrophic-cliff architectures, Vision Token Re-encoder (VTR) recovers 60\\%+ success rate at 75\\% compression where all deletion methods yield 0\\%, with a relatively stable M-curve ($M{=}16 \\approx M{=}128$) confirming learned re-encoding as the key factor. CV diagnosis followed by connector-appropriate compression forms a diagnostic protocol for safe VLA token reduction.",
          "+Removing 5\\% of vision tokens collapses SmolVLA from 59.2\\% to 0.0\\% success rate, while the same reduction on $\\pi_0.5$ retains 98.2\\%. Token pruning, well-established for Vision Transformers, transfers unpredictably across Vision-Language-Action (VLA) models because the vision connector governs token compressibility. We analyze this sensitivity along two axes: connector coupling (token-independent vs.\\ token-entangling) and task complexity (single-step vs.\\ multi-step manipulation). The coefficient of variation (CV) of post-connector token L2 norms, ranging from 0.038 to 0.314 across models, serves as a single-pass diagnostic that correlates with both pruning tolerance and method sensitivity. Token-entangling connectors exhibit task-amplified collapse: X-VLA retains its full 99.2\\% baseline on single-step Object manipulation at 90\\% retention but loses 27.8 percentage points on multi-step Goal tasks at the same ratio. Low-CV models show 15$\\times$ greater sensitivity to pruning method choice than higher-CV models, and at aggressive compression random selection outperforms L2 norm ranking by 36 percentage points for low-CV architectures. For pixel-shuffle connectors where all pruning strategies yield 0.0\\%, Vision Token Re-encoder (VTR), a lightweight cross-attention module, recovers over 60\\% success rate at 75\\% compression through learned re-encoding. Evaluation spans six VLAs (450M to 7B parameters), three connector families, and four LIBERO task suites.",
          " \\end{abstract}"
        ]
      }
    ],
    "originalFile": "\\begin{abstract}\nVision token pruning accelerates Vision Transformer inference with negligible accuracy loss, but whether this robustness transfers to Vision-Language-Action (VLA) models remains untested across architectures. We study seven VLA models (450M--7B parameters) spanning three vision connector families, evaluating four in closed-loop robotic manipulation (LIBERO) and analyzing three via offline metrics or literature. The vision connector is strongly associated with pruning behavior along a four-class compressibility spectrum. Uniformly critical models ($\\pi_0$, $\\pi_0.5$; CV $< 0.06$) tolerate random subsampling but collapse under importance-based selection: $\\pi_0.5$ retains 69.4\\% success rate with random removal at 50\\% retention but drops to 33.4\\% under L2 norm selection, a 36 percentage-point gap demonstrating that offline pruning tolerance does not guarantee closed-loop robustness. Threshold-graded models (X-VLA; CV $= 0.151$) maintain $97.8 \\pm 0.4$\\% through 90\\% retention before cliffing at 85\\% ($-$31\\,pp). Smooth graded models (OpenVLA, OFT; CV $\\approx 0.22$) degrade proportionally. Catastrophic cliff models (SmolVLA; CV $= 0.314$) collapse to 0\\% at 5\\% removal across all seven tested configurations. The coefficient of variation (CV) of token L2 norms serves as a zero-cost diagnostic metric that correlates with both the tolerance class and the optimal pruning strategy from a single forward pass. The gap between random and L2 norm selection scales monotonically with CV at both 50\\% and 70\\% retention across three models. For catastrophic-cliff architectures, Vision Token Re-encoder (VTR) recovers 60\\%+ success rate at 75\\% compression where all deletion methods yield 0\\%, with a relatively stable M-curve ($M{=}16 \\approx M{=}128$) confirming learned re-encoding as the key factor. CV diagnosis followed by connector-appropriate compression forms a diagnostic protocol for safe VLA token reduction.\n\\end{abstract}\n",
    "userModified": false
  }
}
```

</details>

---

### Assistant

_source line 25_

Abstract written (~195 words). Opens with the SmolVLA vs. $\pi_0.5$ finding, covers all required numbers (59.2% → 0.0%, 98.2%, 99.2%, -27.8pp, 15×, 36pp, 60%+, CV 0.038-0.314, 6 VLAs 450M-7B), uses "correlates with" for CV, no em-dashes, no banned words, no citations.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": "assistant",
  "type": "assistant",
  "parent_tool_use_id": null,
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "uuid": "5a8bbd73-fb23-492d-a23c-bc9a8d020eec",
  "message": {
    "model": "claude-opus-4-6",
    "id": "msg_017r7kRJLfbSmbLctpwRvSRK",
    "type": "message",
    "stop_reason": null,
    "stop_sequence": null,
    "stop_details": null,
    "usage": {
      "input_tokens": 1,
      "cache_creation_input_tokens": 821,
      "cache_read_input_tokens": 51813,
      "cache_creation": {
        "ephemeral_5m_input_tokens": 0,
        "ephemeral_1h_input_tokens": 821
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

_source line 26_

Abstract written (~195 words). Opens with the SmolVLA vs. $\pi_0.5$ finding, covers all required numbers (59.2% → 0.0%, 98.2%, 99.2%, -27.8pp, 15×, 36pp, 60%+, CV 0.038-0.314, 6 VLAs 450M-7B), uses "correlates with" for CV, no em-dashes, no banned words, no citations.

<details><summary>Recorded metadata</summary>

```json
{
  "recorded_role": null,
  "type": "result",
  "subtype": "success",
  "is_error": false,
  "api_error_status": null,
  "duration_ms": 269554,
  "duration_api_ms": 270411,
  "num_turns": 9,
  "stop_reason": "end_turn",
  "session_id": "d38aad34-7016-4a01-b8e8-5b15470d1db7",
  "total_cost_usd": 0.5619597500000001,
  "usage": {
    "input_tokens": 7,
    "cache_creation_input_tokens": 40793,
    "cache_read_input_tokens": 182997,
    "output_tokens": 8539,
    "server_tool_use": {
      "web_search_requests": 0,
      "web_fetch_requests": 0
    },
    "service_tier": "standard",
    "cache_creation": {
      "ephemeral_1h_input_tokens": 40793,
      "ephemeral_5m_input_tokens": 0
    },
    "inference_geo": "",
    "iterations": [
      {
        "input_tokens": 1,
        "output_tokens": 118,
        "cache_read_input_tokens": 51813,
        "cache_creation_input_tokens": 821,
        "cache_creation": {
          "ephemeral_5m_input_tokens": 0,
          "ephemeral_1h_input_tokens": 821
        },
        "type": "message"
      }
    ],
    "speed": "standard"
  },
  "modelUsage": {
    "claude-haiku-4-5-20251001": {
      "inputTokens": 1905,
      "outputTokens": 18,
      "cacheReadInputTokens": 0,
      "cacheCreationInputTokens": 0,
      "webSearchRequests": 0,
      "costUSD": 0.001995,
      "contextWindow": 200000,
      "maxOutputTokens": 32000
    },
    "claude-opus-4-6": {
      "inputTokens": 7,
      "outputTokens": 8539,
      "cacheReadInputTokens": 182997,
      "cacheCreationInputTokens": 40793,
      "webSearchRequests": 0,
      "costUSD": 0.5599647500000001,
      "contextWindow": 200000,
      "maxOutputTokens": 64000
    }
  },
  "permission_denials": [],
  "terminal_reason": "completed",
  "fast_mode_state": "off",
  "uuid": "fb53af22-4b25-4642-b6f2-6ef41a221fd7"
}
```

</details>

---
