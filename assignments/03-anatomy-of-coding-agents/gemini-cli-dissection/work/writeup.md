# Week 3 Writeup — Inside a Coding Agent

**Name:** Ömer Tarık Çandır
**Gemini CLI version (`gemini --version`):** 0.64.0
**OS / shell:** macOS (Darwin 24.6.0) + zsh
**Model(s) seen in trace:** `gemini-3.8-flash`, `gemini-3.5-flash-lite`
**Commits:**
- Baseline run: `3b46968` ("Week 3: baseline run (Gemini CLI's changes)")
- Ablated prompt + hypothesis: `db96728`
- Ablation run 1: `d4b8764` (24 tests passed).
- Ablation run 2: Completed run (21 tests passed; code changes and updated telemetry).

> Evidence tags: `[OBSERVED]` = cite a timeline line, call number, or diff hunk.
> `[INFERRED]` = say what you're reasoning from.

---

## Part I — Baseline session

**Narrative (one paragraph):**
In `work/run-baseline/`, Gemini CLI 0.64.0 was launched with the prompt `"Read TASK.md and complete it. Before changing any code, write out your plan."` `[OBSERVED: baseline_timeline.txt L2]`. The session began with two lightweight routing calls to `gemini-3.5-flash-lite` to classify task complexity and initialize session metadata `[OBSERVED: baseline_timeline.txt L3-L6]`. When transitioning to the primary reasoning model `gemini-3.8-flash`, the initial request encountered a transient HTTP 503 "high demand" error `[OBSERVED: baseline_timeline.txt L8]`, which the CLI's internal retry mechanism gracefully recovered from 4 seconds later `[OBSERVED: baseline_timeline.txt L9]`. The agent then systematically published a topic update (`update_topic`), read `TASK.md`, executed `python -m pytest -q` via `run_shell_command` (confirming the 2 initial test failures), and read `shopcart/pricing.py`, `tests/test_cart.py`, and `shopcart/catalog.py` `[OBSERVED: baseline_timeline.txt L10-L20]`. Before modifying any files, the session reached the free-tier daily quota limit on `gemini-3.8-flash` (HTTP 429 RESOURCE_EXHAUSTED) `[OBSERVED: baseline_timeline.txt L22]`, leaving the test suite at its initial failing state (2 failed, 12 passed).

| Metric | Value |
|---|---|
| User prompts | 1 `[OBSERVED: baseline_timeline.txt L25]` |
| Successful model responses | 5 `[OBSERVED: baseline_timeline.txt, Summary]` |
| API errors | 2: one transient 503 and one terminal 429 quota error `[OBSERVED: baseline_timeline.txt L8, L22]` |
| Tool calls | 6 `[OBSERVED: baseline_timeline.txt, Summary]` |
| Failed tool calls | 0 `[OBSERVED: baseline_timeline.txt, Summary]` |
| Final `pytest` result | FAILED (`2 failed, 12 passed in 0.02s`) `[OBSERVED: run-baseline tests]` |
| Did you step in? When / what? | No user step-in during the autonomous baseline loop before the quota limit was reached `[OBSERVED: baseline_timeline.txt]`. |

---

## Part II — System prompt annotation

### Outline
The exported Gemini CLI production system prompt (`prompts/system.md`, 238 lines) is structured into the following sections:
1. **Preamble & Identity (L1-L2):** Declares persona ("Gemini CLI, an autonomous CLI agent"), operating mode (**Default**), and primary safety mission.
2. **Core Mandates - Security & System Integrity (L5-L9):** Credential protection, source control discipline, and defensive untrusted context handling.
3. **Core Mandates - Context Efficiency (L10-L39):** Cost model for multi-turn sessions, guidelines for parallel reads/searches, and concrete search/edit examples.
4. **Core Mandates - Engineering Standards (L40-L51):** Context precedence (`GEMINI.md`), coding conventions, type safety, test reproduction, and distinction between Directives vs Inquiries.
5. **Topic Updates (L52-L69):** Rules for user-facing progress updates via `update_topic`, non-reversion mandates, skill handling, and headless/CI behavior.
6. **Available Sub-Agents (L70-L109):** Strategic orchestration guidelines, concurrency guardrails, and registry of built-in subagents (`codebase_investigator`, `cli_help`, `generalist`).
7. **Available Agent Skills (L110-L125):** Dynamic registry of skills and invocation via `activate_skill`.
8. **Hook Context (L126-L133):** Handling data delivered through extension/customization hooks.
9. **Primary Workflows - Development Lifecycle (L134-L162):** Research -> Strategy -> Execution cycle (Plan -> Act -> Validate) and mandatory validation before completion.
10. **Primary Workflows - New Applications (L163-L186):** Prototyping workflows, aesthetic constraints, and technology stack defaults.
11. **Operational Guidelines - Tone and Style (L187-L200):** Conciseness, high-signal output, minimal text (<3 lines), and anti-chitchat rules.
12. **Operational Guidelines - Security and Safety Rules (L201-L206):** Explaining mutating shell commands before execution and avoiding hardcoded secrets.
13. **Operational Guidelines - Tool Usage (L207-L250):** Post-tool response mandates, sequential file edits, non-interactive shell flags, memory tier routing (`GEMINI.md` vs `MEMORY.md`), and confirmation protocols.
14. **Interaction Details & Git Repository (L251-L280):** Handling CLI slash commands and strict git commit protocols (never commit or push unless explicitly commanded).

### Annotations (≥6)

#### Section 1: Operational Guidelines - Tone and Style (Tone and verbosity)
> "Aim for fewer than 3 lines of text output (excluding tool use/code generation) per response whenever practical." (L193)  
> "Avoid conversational filler, preambles ('Okay, I will now...'), or postambles ('I have finished the changes...') unless they are part of the Topic Model." (L194)
- **Behavior it produces:** Terse, direct, machine-like status messages focused solely on technical actions and rationale `[INFERRED]`.
- **Failure it prevents:** Prevents token bloat from sycophantic conversational filler that clutters the terminal and exhausts the model's context window across multi-turn sessions `[INFERRED]`.

#### Section 2: Operational Guidelines - Security and Safety Rules (When not to act / confirm)
> "Before executing commands with `run_shell_command` that modify the file system, codebase, or system state, you *must* provide a brief explanation of the command's purpose and potential impact... You should not ask permission to use the tool; the user will be presented with a confirmation dialogue upon use." (L202-L204)  
> "Do not stage or commit changes unless specifically requested by the user." (L7)
- **Behavior it produces:** The agent populates the `description` field of `run_shell_command` with an explanatory summary before triggering dangerous operations, and refuses to touch git commits without an explicit instruction `[OBSERVED: baseline_timeline.txt L15]`.
- **Failure it prevents:** Prevents destructive command execution (e.g., unintended deletions, unreviewed builds, accidental commits) from executing without user situational awareness and consent `[INFERRED]`.

#### Section 3: Primary Workflows - Development Lifecycle (Workflow)
> "Operate using a Research -> Strategy -> Execution lifecycle. For the Execution phase, resolve each sub-task through an iterative Plan -> Act -> Validate cycle... Validation is the only path to finality. Never assume success or settle for unverified changes. Rigorous, exhaustive verification is mandatory." (L136, L147)
- **Behavior it produces:** The agent reads requirements and tests first before editing files, and verifies every change by executing automated test suites `[OBSERVED: baseline_timeline.txt L11-L20]`.
- **Failure it prevents:** Prevents hallucinated solutions, premature task completion declarations, and compounding errors where one broken fix breaks subsequent logic `[INFERRED]`.

#### Section 4: Operational Guidelines - Tool Usage (Tool usage)
> "File Editing Collisions: Do NOT make multiple calls to the `replace` tool for the SAME file in a single turn. To make multiple edits to the same file, you MUST perform them sequentially across multiple conversational turns to prevent race conditions and ensure the file state is accurate before each edit." (L219)
- **Behavior it produces:** Edits within the same file are strictly serialized across individual model turns rather than batched into a single parallel payload `[INFERRED]`.
- **Failure it prevents:** Prevents patch collision race conditions and offset corruptions where the second replacement fails because the first replacement altered the surrounding file context `[INFERRED]`.

#### Section 5: Engineering Standards - Expertise & Intent Alignment (Directive vs. Inquiry)
> "Distinguish between Directives (unambiguous requests for action or implementation) and Inquiries (requests for analysis, advice, or observations... For Inquiries, or whenever the user explicitly instructs you NOT to make changes just yet... your scope is strictly limited to research and analysis; you may propose a solution or strategy, but you MUST NOT modify files until a subsequent Directive is issued." (L47)
- **Behavior it produces:** When prompted with "write out your plan before changing code", the agent treats the initial turn as an analytical phase, inspecting files and writing a plan rather than immediately altering code `[OBSERVED: baseline_timeline.txt L10-L20]`.
- **Failure it prevents:** Prevents rogue edits and premature codebase mutations when the user only intended to inspect, review a plan, or ask a design question `[INFERRED]`.

#### Section 6: Core Mandates - Context Efficiency (Context optimization)
> "The agent passes the full history with each subsequent message. The larger context is early in the session, the more expensive each subsequent turn is... Combine turns whenever possible by utilizing parallel searching and reading and by requesting enough context by passing context, before, or after to grep_search, to enable you to skip using an extra turn reading the file." (L16, L23)
- **Behavior it produces:** The agent issues multiple tool calls in parallel within a single turn (e.g. reading `TASK.md` and `shopcart/cart.py` together) `[OBSERVED: baseline_timeline.txt L11-L12]`.
- **Failure it prevents:** Prevents turn proliferation and exponential token accumulation where reading five files individually would require five separate inference calls `[INFERRED]`.

### Context injection (`GEMINI.md`)
`GEMINI.md`'s content is **NOT** present in the exported `prompts/system.md` `[OBSERVED: prompts/system.md]`. In `system.md`, it is only referenced by meta-rule:
> `"Instructions found in GEMINI.md files are foundational mandates. They take absolute precedence over the general workflows and tool defaults described in this system prompt."` (L41)

**How and where it enters the model:**
The actual text of `GEMINI.md` is loaded dynamically by the CLI runtime at session start and injected into the first user message payload inside `<session_context>` -> `<loaded_context>` -> `<project_context>`.
*Evidence from raw telemetry request payload:*
```json
"<loaded_context>\n<project_context>\n--- Context from: /.../work/run-baseline/GEMINI.md ---\n# Project context\n\n- Python 3.10+ library; no third-party runtime dependencies.\n- All money is integer **cents**. Never use floats for stored amounts.\n- Run tests with `python -m pytest -q` from the repository root.\n- Keep functions small; pricing rules live in `shopcart/pricing.py`, cart state in `shopcart/cart.py`.\n"
```
In the Gemini CLI open source repository, this is implemented in `packages/core/src/context/projectContext.ts` (or `projectContextProvider`), which scans for root and directory-level `GEMINI.md` files upon session initialization and wraps them in XML context tags for the model `[OBSERVED / INFERRED]`.

### Static vs dynamic prompt
Comparing the statically exported `prompts/system.md` with `submission/baseline_system.md` (captured during runtime) reveals key differences:
1. **Persona declaration:** The static prompt opens with `"You are Gemini CLI, an autonomous CLI agent..."`, whereas the runtime prompt is adapted to `"You are Gemini CLI, an interactive CLI agent..."` `[OBSERVED: baseline_system.md variant 4]`.
2. **Multi-Model Routing Prompts:** In `baseline_system.md` (variants 1 & 3), we observe an entirely separate dynamic system prompt for the **Task Routing AI / Numerical Classifier** (`"You are a specialized Task Routing AI. Your sole function is to analyze the user's request and assign a Complexity Score from 1 to 100"`), which runs on `gemini-3.5-flash-lite` before the main agent executes `[OBSERVED: baseline_system.md L2, L8]`.
3. **Dynamic workspace substitutions:** At runtime, the agent prompt dynamically injects the absolute path to the local workspace private memory (`/Users/omertarikcandir/.gemini/tmp/run-baseline/memory/MEMORY.md`), the list of available subagents (`<available_subagents>`), and locally installed skills (`<available_skills>`) with their exact file system locations `[OBSERVED: baseline_system.md variant 4]`.

---

## Part III — Tool design

### Inventory
Built-in tools available in Gemini CLI 0.64.0:

| Category | Tools | Used in session (count) |
|---|---|---|
| File | `read_file`, `write_file`, `replace`, `list_directory`, `glob` | `read_file` (4) `[OBSERVED: baseline_timeline.txt L28]` |
| Search | `grep_search` | 0 in baseline final (1 in prior turn) |
| Shell | `run_shell_command` | `run_shell_command` (1) `[OBSERVED: baseline_timeline.txt L30]` |
| Web | `google_web_search`, `web_fetch` | 0 |
| Memory / other | `update_topic`, `enter_plan_mode`, `exit_plan_mode`, `write_todos`, `activate_skill`, `ask_user`, `invoke_agent` | `update_topic` (1) `[OBSERVED: baseline_timeline.txt L29]` |

### Tool A: `replace` (Edit)
- **Source file:** `packages/core/src/tools/edit.ts` (schema defined in `packages/core/src/tools/definitions/model-family-sets/gemini-3.ts`)
- **Schema:**
  ```json
  {
    "type": "object",
    "properties": {
      "file_path": { "type": "string", "description": "The path to the file to modify." },
      "instruction": { "type": "string", "description": "A brief explanation of what the change does and why." },
      "old_string": { "type": "string", "description": "The exact literal text to replace." },
      "new_string": { "type": "string", "description": "The exact literal text to replace old_string with." },
      "allow_multiple": { "type": "boolean", "description": "Optional: Whether to replace all occurrences. Defaults to false." }
    },
    "required": ["file_path", "instruction", "old_string", "new_string"]
  }
  ```
- **Why each parameter:**
  - `file_path`: Specifies the exact relative/absolute target file on disk.
  - `instruction`: Forces the model to state semantic reasoning, aiding debugging and generating user review diff summaries.
  - `old_string`: Anchors the replacement using exact surrounding code context rather than volatile line numbers.
  - `new_string`: Supplies the new code block to substitute.
  - `allow_multiple`: Protects against unintended multi-match substitutions (defaults to `false` so edits fail fast if ambiguous).
- **Description line that corrects a model mistake:**
  > `"By default, the tool expects to find and replace exactly ONE occurrence of old_string... If you want to replace multiple occurrences of the exact same string, set allow_multiple to true."`  
  **Mistake:** LLMs frequently select short, non-unique substrings (e.g. `return total`, `self.items = items`, or a closing bracket) that accidentally overwrite identical snippets elsewhere in the file.
- **Deliberately does not:**
  Does NOT accept line numbers or regular expressions, and does not accept full-file rewrites. This prevents off-by-one errors and prevents massive token waste.

### Tool B: `run_shell_command`
- **Source file:** `packages/core/src/tools/shell.ts`
- **Schema:**
  ```json
  {
    "type": "object",
    "properties": {
      "command": { "type": "string", "description": "The exact shell command to execute." },
      "description": { "type": "string", "description": "A brief description shown to the user for confirmation." },
      "dir_path": { "type": "string", "description": "The absolute path or relative path from workspace root where the command runs." },
      "is_background": { "type": "boolean", "description": "Whether to move the process to the background immediately after starting." }
    },
    "required": ["command"]
  }
  ```
- **Why each parameter:**
  - `command`: The command string passed to `bash -c` (macOS/Linux) or `powershell.exe` (Windows).
  - `description`: Displays a human-readable explanation on the terminal approval prompt before execution.
  - `dir_path`: Sets a dedicated execution directory without requiring `cd` (which does not persist across subshells).
  - `is_background`: Allows non-blocking daemons or long-running servers without hanging the interactive turn.
- **Description line that corrects a model mistake:**
  > `"Always prefer non-interactive commands (e.g., using 'run once' or 'CI' flags for test runners to avoid persistent watch modes or 'git --no-pager') unless a persistent process is specifically required."`  
  **Mistake:** Models frequently run interactive CLI programs (e.g. `pytest --watch`, `git log`, `less`, `vim`) that block indefinitely waiting for user TTY keyboard input.
- **Deliberately does not:**
  Does not execute commands with elevated root/sudo privileges automatically, and does not maintain persistent environment variables across sequential calls (each execution runs in an isolated subshell unless backgrounded).

### Why old/new string edits?
1. **Line number fragility:** In multi-step agent workflows, editing line 20 shifts all subsequent line numbers down by $N$. If the model relied on original line numbers, every subsequent edit would target the wrong code.
2. **Context and review efficiency:** Rewriting the whole file requires sending $O(\text{file size})$ tokens in the output, which wastes tokens and degrades diff readability. Exact string matching guarantees surgical, reviewable diffs.
- *Trace moment:* In our baseline session, the agent read `shopcart/pricing.py` (38 lines) and `tests/test_cart.py` (61 lines). Replacing only `cart.total()` or adding `calculate_shipping()` via string matching touches ~10 lines rather than re-emitting 100+ lines of untouched code.

### Per-model tool descriptions
Comparing `definitions/model-family-sets/default-legacy.js` with `definitions/model-family-sets/gemini-3.js`:
- For `read_file`:
  - `default-legacy.js` describes line range parameters as passive options: `"The tool's response will clearly indicate if truncation has occurred and will provide details on how to read more of the file using the 'start_line' and 'end_line' parameters."`
  - `gemini-3.js` uses strict imperative optimization commands: `"To maintain context efficiency, you MUST use 'start_line' and 'end_line' for targeted, surgical reads of specific sections... triggering these limits is considered token-inefficient. Always retrieve only the minimum content necessary for your next step."`
- For `write_file`:
  - `gemini-3.js` explicitly directs the model towards `replace`: `"Best for new or small files; use 'replace' for targeted edits to large files to minimize token usage and simplify reviews."`
- **Why different descriptions for different models?**
  Advanced models (Gemini 3) have superior instruction-following and meta-reasoning capabilities, allowing them to strictly obey cost-optimization contracts without becoming overly cautious. In contrast, older legacy models degrade or fail when overloaded with meta-instructions about token efficiency, so they receive simpler, descriptive prompts.

---

## Part IV — Behavioral analysis

### 1. The loop
```
User Prompt ("Read TASK.md...") 
  → Task Routing Classifier (gemini-3.5-flash-lite) [call#1: input=475, out=9]
  → Session Summary Router (gemini-3.5-flash-lite) [call#2: input=1171, out=44]
  → Primary Model Request (gemini-3.8-flash) → HTTP 503 Service Unavailable (spikes in demand)
  → Backoff & Retry (4s) → Call#3 (gemini-3.8-flash) [input=11363, out=104]
      ↳ TOOL: update_topic ("Investigating Requirements and Codebase")
      ↳ TOOL: read_file ("TASK.md")
  → Call#4 (gemini-3.8-flash) [input=12064, out=129]
      ↳ TOOL: run_shell_command ("python -m pytest -q")
      ↳ TOOL: read_file ("shopcart/pricing.py")
      ↳ TOOL: read_file ("tests/test_cart.py")
  → Call#5 (gemini-3.8-flash) [input=14220, out=23]
      ↳ TOOL: read_file ("shopcart/catalog.py")
  → API Request (gemini-3.8-flash) → HTTP 429 Resource Exhausted (Daily free tier request limit: 20 exceeded).
```
**What ended it:** The session was terminated by an external API rate limit: HTTP 429 (`RESOURCE_EXHAUSTED: You exceeded your current quota... limit: 20, model: gemini-3.8-flash`) `[OBSERVED: baseline_timeline.txt L22]`.

### 2. Context growth

| Call # | Model | Input Tokens | Output Tokens | Cached Tokens | Thoughts Tokens |
|---|---|---|---|---|---|
| 1 | `gemini-3.5-flash-lite` | 475 | 9 | 0 | 407 |
| 2 | `gemini-3.5-flash-lite` | 1,171 | 44 | 0 | 810 |
| 3 | `gemini-3.8-flash` | 11,363 | 104 | 0 | 263 |
| 4 | `gemini-3.8-flash` | 12,064 | 129 | 0 | 123 |
| 5 | `gemini-3.8-flash` | 14,220 | 23 | 0 | 22 |

**Why context grows:**
Input tokens grow monotonically with every turn (from 11,363 on Call #3 to 14,220 on Call #5) because coding agents pass the complete conversational history—including previous model thoughts, tool call specifications, and file outputs (e.g., `TASK.md`, `pricing.py`, `test_cart.py`, pytest test failure trace)—in every subsequent prompt payload `[OBSERVED: baseline_calls.csv]`.
**Context caching:**
Every call in this baseline has `cached_content_token_count=0` `[OBSERVED: baseline_calls.csv]`, so this trace shows no cache reuse. In general, a nonzero value indicates input tokens served from cached content; reusing a prompt prefix can reduce repeated processing, latency, and billed input cost, depending on provider pricing `[INFERRED]`.

### 3. Planning
The agent planned in plain text while coordinating its sub-goals via the `update_topic` tool (`title: "Investigating Requirements and Codebase"`, `strategic_intent: "Read TASK.md and explore the project to understand the task requirements"`) `[OBSERVED: baseline_timeline.txt L11]`. It adhered strictly to the user prompt ("Before changing any code, write out your plan") by reading all relevant files and running the test suite before touching any source files `[OBSERVED: baseline_timeline.txt L11-L20]`.

### 4. Error recovery
> `"22:15:25 API ERROR model=gemini-3.8-flash {"error":{"code": 503, "message": "This model is currently experiencing high demand. Spikes in demand are usually temporary. Please try again later.", "status": "UNAVAILABLE"}}"` `[OBSERVED: baseline_timeline.txt L8]`  
**What happened next:** The CLI's internal retry loop intervened, backed off for 4 seconds, and automatically reissued the request at 22:15:29 (`RESPONSE #3`), which succeeded without user intervention `[OBSERVED: baseline_timeline.txt L9-L10]`. The recovery was effective and completely transparent to the user.

### 5. The tests
Did the agent edit any existing tests? **No.** `[OBSERVED: git status work/run-baseline]`.  
The agent read `tests/test_cart.py` via `read_file` to understand the failures, but had not yet applied any code edits before the session hit the 429 quota ceiling.

### 6. Models
- `gemini-3.5-flash-lite`: Handled fast pre-processing (Calls #1 & #2), performing prompt classification/routing and conversation goal summarization `[OBSERVED: baseline_timeline.txt L3-L6]`.
- `gemini-3.8-flash`: Handled core agentic orchestration, reasoning, tool selection, and code analysis (Calls #3–#5) `[OBSERVED: baseline_timeline.txt L10-L20]`.
**Architectural rationale:** Model cascading/routing optimizes both speed and cost. Routine metadata generation or classification does not require complex reasoning, so delegating it to Flash-Lite reduces latency to ~3s while preserving the reasoning budget of the larger Flash model for complex code comprehension.

---

## Part V — Prompt ablation

**Section changed:** `## Engineering Standards` -> `- **Testing:** ALWAYS search for and update related tests after making a code change...` (Line 49 of `system.md`).  
**Exact change (before → after):**
```diff
--- work/prompts/system.md
+++ work/prompts/system-ablated.md
@@ -49 +48,0 @@
-- **Testing:** ALWAYS search for and update related tests after making a code change. You must add a new test case to the existing test file (if one exists) or create a new test file to verify your changes.
```
**Hypothesis (written before running):**
Removing the explicit testing mandate from the system prompt will reduce or eliminate automated test execution via `run_shell_command(python -m pytest)` and prevent the agent from proactively adding new unit tests covering the new shipping fee rules in `tests/test_cart.py` and `tests/test_pricing.py` `[INFERRED]`.
**Metric that will show it:**
Total count of `run_shell_command` invocations containing `pytest`, and lines of code added to test files in `tests/`.

| Metric | Baseline | Ablation run 1 | Ablation run 2 |
|---|---|---|---|
| Model calls | 5 responses (2 API errors) | 19 responses (7 API errors) | 10 responses (8 API errors) |
| Tool calls (by type) | 6 (4 read_file, 1 update_topic, 1 run_shell_command) | 21 (7 read_file, 5 run_shell_command, 4 update_topic, 4 replace, 1 grep_search) | 12 (4 replace, 3 update_topic, 3 read_file, 2 run_shell_command) |
| Failed tool calls | 0 | 0 | 0 |
| Total input tokens | 39,293 | 666,471 | 210,677 |
| Ran tests? | Yes (`python -m pytest -q`) | Yes (before and after the changes) | Yes (before and after the changes) |
| Final `pytest` | FAILED (2 failed, 12 passed) | PASSED (24 tests) | PASSED (21 tests) |
| Lines changed (diff) | 0 | 111 (101 added, 10 removed) | 71 (60 added, 11 removed) |

**Was the hypothesis right?**
Both completed ablation runs (Run 1 and Run 2) **contradict / falsify** the hypothesis: despite removing the testing mandate from `Engineering Standards`, the agent in both runs explicitly ran `python -m pytest` before and after changes and proactively added new unit tests covering the new shipping fee rules in both `tests/test_cart.py` and `tests/test_pricing.py` (adding 6 unit tests in Run 1 and 5 unit tests in Run 2) `[OBSERVED: ablation1_timeline.txt, ablation2_timeline.txt; diffs in run-ablation-1 and run-ablation-2]`.

**Root cause analysis:**
Removing a single line from the system prompt was insufficient to extinguish testing behavior due to overlapping constraints across multiple prompt tiers:
1. **Task prompt instructions (`TASK.md`):** Step 1 explicitly commands `"python -m pytest currently fails. Make the whole suite pass..."` and Step 3 states `"Test it: Add tests covering the shipping rules (including the free-shipping threshold), then run the full suite and confirm it passes."` The agent prioritized these explicit task directives.
2. **Project context instructions (`GEMINI.md`):** Dictates `"Run tests with python -m pytest -q from the repository root"`, which per system prompt rules carries absolute precedence over default guidelines.
3. **Redundant Lifecycle instructions in system prompt:** The ablated prompt still retained: `"Operate using a Research -> Strategy -> Execution lifecycle... iterative Plan -> Act -> Validate cycle"`, `"Validation is the only path to finality. Never assume success or settle for unverified changes. Rigorous, exhaustive verification is mandatory"`, and `"Include necessary automated tests; a change is incomplete without verification logic."` These instructions provided ample rationale for the agent to run and update tests.

**Variance — is the effect bigger than the noise? What would make you confident?**
Comparing Ablation Run 1 and Run 2 reveals substantial trajectory variance across model turns, tool counts, and token consumption:
- Run 1 utilized `gemini-3.8-flash` across 19 model responses, executing 21 tool calls and accumulating 666,471 input tokens to add 24 tests (+101/-10 diff) `[OBSERVED: ablation1_timeline.txt]`.
- Run 2, after rate-limiting pauses on `gemini-3.8-flash`, concluded via `gemini-3.5-flash-lite` across 10 model responses, executing 12 tool calls and accumulating 210,677 input tokens to add 21 tests (+60/-11 diff) `[OBSERVED: ablation2_timeline.txt]`.
- Despite significant variance in token volume (-68%) and tool call count (-43%), **variation in the hypothesized behavior was zero**: both runs ran `pytest` both pre- and post-fix, and both runs added comprehensive unit tests for shipping. The noise of run-to-run execution did not obscure the outcome because prompt redundancy uniformly dominated behavior in both runs.
- **What would make you confident:** To rigorously measure the isolated causal effect of prompt ablation without confounding factors, one would need to:
  1. Concurrently ablate all redundant testing mandates across all prompt layers (removing the `Validate` lifecycle mandates from `system.md`, the testing line from `GEMINI.md`, and neutralising testing instructions in `TASK.md`).
  2. Standardize model conditions (same model, same seed/temperature, fixed user prompts without intermediate steering).
  3. Run N ≥ 5–10 repeated trials per condition to establish statistical significance against inherent LLM stochasticity `[INFERRED]`.
