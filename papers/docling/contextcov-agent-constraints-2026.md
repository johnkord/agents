## ContextCov: Deriving and Enforcing Executable Constraints from Agent Instruction Files

Reshabh K Sharma

University of Washington Seattle, Washington, USA reshabh@cs . washington . edu environments without human oversight. As agent autonomy increases, certain classes of constraints become increasingly difficult to monitor manually. Style violations blend into large diffs, architectural boundary crossings require mental tracking of module dependencies, and build workflow deviations may not surface until much later.

This shift motivates a fundamental change in how we communicate constraints to agents. The specification can no longer reside solely in the developer's mind or in transient chat history. It must be externalized and persistent.

To bridge this gap, we introduce ContextCov, a framework that transforms passive Agent Instructions into active, executable guardrails. ContextCov extracts natural language constraints and synthesizes enforcement checks across three domains: static AST analysis for code patterns, runtime shell shims that intercept prohibited commands, and architectural validators for structural and semantic constraints. Evaluations on 723 open-source repositories demonstrate that ContextCov successfully extracts over 46,000 executable checks with 99.997% syntax validity, providing a necessary automated compliance layer for safe, agent-driven development. Source code and evaluation results are available at https://anonymous . 4open . science/r/ContextCov-4510/.

## Abstract

As Large Language Model (LLM) agents increasingly execute complex, autonomous software engineering tasks, developers rely on natural language Agent Instructions (e.g., AGENTS.md ) to enforce project-specific coding conventions, tooling, and architectural boundaries. However, these instructions are passive text. Agents frequently deviate from them due to context limitations or conflicting legacy code, a phenomenon we term Context Drift . Because agents operate without real-time human supervision, these silent violations rapidly compound into technical debt.

## ACMReference Format:

Reshabh K Sharma. 2026. ContextCov: Deriving and Enforcing Executable Constraints from Agent Instruction Files. In . ACM, New York, NY, USA, 10 pages. https://doi . org/10 . 1145/nnnnnnn . nnnnnnn

## 1 Introduction

Large language model agents are fundamentally changing how software is developed. Early tools like GitHub Copilot operated as autocomplete engines with instantaneous human verification. Chat-based interfaces such as Cursor [24] allowed developers to delegate larger tasks, but the developer remained an active supervisor. We are now entering the era of autonomous agents. Tools like GitHub Copilot Workspace [32], Devin [22], SWE-Agent [61], and OpenHands [59] operate asynchronously to complete high-level objectives, with benchmarks like SWE-bench [38] driving rapid capability improvements. These agents often run for hours in cloud

Permission to make digital or hard copies of all or part of this work for personal or classroom use is granted without fee provided that copies are not made or distributed for profit or commercial advantage and that copies bear this notice and the full citation on the first page. Copyrights for components of this work owned by others than the author(s) must be honored. Abstracting with credit is permitted. To copy otherwise, or republish, to post on servers or to redistribute to lists, requires prior specific permission and/or a fee. Request permissions from permissions@acm.org.

Conference'17, Washington, DC, USA

ACM ISBN 978-x-xxxx-xxxx-x/YYYY/MM

© 2026 Copyright held by the owner/author(s). Publication rights licensed to ACM.

https://doi . org/10 . 1145/nnnnnnn . nnnnnnn

The Rise of Agent Instructions. To bridge this supervision gap, the developer community has organically adopted Agent Instruction files . Stored in files such as AGENTS.md , CLAUDE.md , or copilot-instructions.md , these documents define the rules of engagement for autonomous agents. The agents.md website [8] reports that over 60,000 GitHub repositories now include such files. Recent taxonomic studies have identified over 16 categories of instructions [20], which we organize into three broad categories based on enforcement mechanism. Process constraints govern build commands, package managers, and environment setup (e.g., 'Always use pnpm , never npm '). Source constraints specify style guides, naming conventions, and API preferences (e.g., 'Use arrow functions over anonymous function expressions'). Architectural constraints define module dependencies and layer restrictions (e.g., 'The UI layer must not import from the database layer').

Two distinct challenges contribute to Context Drift. The first is underspecified instructions , which we do not address since agents cannot follow unspecified constraints. The second, which we focus on, is agent non-compliance . Even when instructions are adequately specified, agents may fail to follow them due to conflicting input, capability limitations, context overload, or codebase patterns that conflict with stated instructions [28, 43]. We term this gap between what agents should do and what they actually do the Reality Gap.

The Problem. Agent Instructions suffer from a critical flaw. They are passive text files, not executable specifications. This introduces the challenge of Context Drift , where an agent produces changes that violate the constraints specified in its instructions. Many constraints are inherently difficult to verify through manual review. Without automated enforcement, violations accumulate silently.

The Reality Gap has severe implications. An agent instructed to 'use pnpm ' but encountering legacy package-lock.json fi les faces an instruction-environment conflict. LLMs often prioritize immediate context over system-level directives [30, 37, 54], leading to non-compliant changes. Similarly, agents optimizing for local task completion may cause architectural erosion [12] by introducing circular dependencies or layer breaches. Perhaps most concerning,

these violations compound over time [45]. When an agent mimics existing patterns that violate instructions, subsequent agent runs continue and amplify the drift.

Contributions. This paper makes the following contributions:

Our Approach. ContextCov addresses this challenge by transforming passive Agent Instructions into active, verifiable invariants. We argue that as agent autonomy increases, Agent Instructions must be treated as executable specifications, not passive documentation but verifiable code that compiles into runtime checks. ContextCov operationalizes this principle through (1) Hierarchical Constraint Extraction , a path-aware parsing algorithm that preserves semantic scope imposed by heading hierarchies, (2) DomainRouted Policy Synthesis , an intent classification system that routes each constraint to specialized code generators for Process, Source, or Architectural enforcement, and (3) Multi-Layer Runtime Enforcement , comprising a Process Interceptor via PATH injection, a Universal Static Linter built on Tree-sitter, and an Architectural Validator using graph algorithms and LLM-based judgment.

- (1) We identify and characterize Context Drift in agent-centric software engineering and present a taxonomy of violation types grounded in analysis of real-world Agent Instruction files (Section 2).
- (3) Wepresent the ContextCov architecture, comprising domainspecialized code synthesis and a runtime enforcement layer (Section 3).
- (2) We introduce a hierarchical, path-aware algorithm for extracting verifiable constraints from Agent Instruction files (Section 3).
- (4) We evaluate ContextCov on 723 open-source repositories, demonstrating that it extracts diverse constraints across multiple enforcement domains (Section 4).

## 2 Motivating Scenarios

We illustrate the challenge of Context Drift through three scenarios based on Visual Studio Code's copilot-instructions.md [6] (Figure 1). Agents may violate constraints because instructions get lost in a growing context window or because the agent fails to follow them correctly. Beyond these obvious cases, we focus on more subtle scenarios where agents violate constraints by mimicking existing code patterns or prioritizing immediate task completion over documented guidelines. ContextCov addresses this by transforming passive instructions into executable checks that provide immediate, actionable feedback to the agent.

## 2.1 Process Violation

Lines 1-6 of Figure 1 specify constraints for the TypeScript build process.

Possible Violation. Consider an agent tasked with 'Fix the failing editor tests' that observes test failures in the CI logs. Trained on common JavaScript and TypeScript workflows, the agent's natural inclination is to run the tests directly, perhaps with npm test or the project's test script. However, VS Code uses a sophisticated incremental watch-based compilation system. Running tests without first verifying compilation creates cascading problems. Tests fail for reasons unrelated to the actual bug, the agent misdiagnoses the issue, and subsequent 'fixes' may introduce new errors. Worse, if

```
1 ## Validating TypeScript changes 2 MANDATORY: Always check the ` VS Code -Build ` watch task 3 output for compilation errors before running ANY script. 4 5 -NEVER run tests if there are compilation errors 6 -NEVER use ` npm run compile ` to compile TypeScript files 7 8 ## Coding Guidelines 9 ### Style 10 -Use arrow functions ` => ` over anonymous function expressions 11 - Only surround arrow function parameters when necessary. 12 For example, ` (x) => x + x ` is wrong but these are correct: 13 x => x + x 14 (x, y) => x + y 15 -Prefer ` async/await ` over ` Promise ` and ` then ` calls 16 17 ### Core Architecture ( ` src/ ` folder) 18 -` src/vs/base/ ` -Foundation utilities 19 -` src/vs/platform/ ` -Platform services and DI 20 -` src/vs/editor/ ` -Text editor implementation 21 -` src/vs/workbench/ ` -Main application workbench 22 -` workbench/browser/ ` -Core workbench UI components 23 -` workbench/services/ ` -Service implementations 24 -` workbench/contrib/ ` -Feature contributions 25 -` workbench/api/ ` -Extension host and VS Code API 26 -**Layered architecture** -from ` base ` to ` workbench ` 27 28 ### Code Quality 29 - You MUST NOT use storage keys of another component only 30 to make changes to that component. You MUST come up with 31 proper API to change another component.
```

Figure 1: Excerpt from VS Code's copilot-instructions.md , a production Agent Instruction file used to guide AI coding assistants. Lines 1-6 define process constraints for the TypeScript build workflow, lines 8-22 specify source-level coding conventions, and lines 24-38 establish architectural boundaries and design principles.

the agent runs npm run compile , which the instructions explicitly forbid, it bypasses the incremental build system and wastes significant time on a full recompilation.

ContextCov addresses this by parsing process constraints and generating checks that intercept shell commands. When an agent attempts to invoke the forbidden npm run compile , it receives immediate feedback:

```
$ npm run compile [ContextCov] BLOCKED: Process constraint violated Rule: "NEVER use npm run compile" Action: Check VS Code - Build watch task output instead.
```

The agent can then adjust to use the proper workflow instead of proceeding with a forbidden command.

More broadly, process violations occur when an agent executes commands that contradict operational constraints. Common patterns include package manager mismatch (e.g., using npm when pnpm is required), using build commands different from those specified, or violating tool version requirements.

## 2.2 Source Violation

Lines 8-22 of Figure 1 specify coding conventions for VS Code.

Possible Violation. Consider an agent tasked with 'Add a new file watcher callback' that writes natural-looking TypeScript:

```
watcher.onDidChange((event) => { this.handleChange(event); });
```

This code is syntactically valid and functionally correct. However, it violates VS Code's style guidelines because the single parameter event should not be parenthesized. The agent may have observed similar patterns in legacy code and mimicked them. Without enforcement, these style inconsistencies would accumulate across the codebase.

ContextCov addresses this by generating a Tree-sitter query that detects arrow functions with unnecessarily parenthesized single parameters. When the static linter runs, it reports the violation with the source location and a suggested fix, enabling the agent to self-correct before commit:

```
[ContextCov] Source violation: src/vs/workbench/watcher.ts:127 Rule: "Only surround arrow function parameters when necessary" Found: (event) => {...} Suggestion: Remove parentheses: event => {...}
```

More broadly, source violations occur when an agent generates code patterns that contradict coding standards. These include using explicitly forbidden patterns (e.g., any types), violating naming conventions or formatting rules, and using deprecated APIs. Agents often introduce these violations by mimicking patterns in existing code, even when those patterns contradict documented standards.

## 2.3 Architectural Violation

Lines 24-38 of Figure 1 define VS Code's architectural constraints. We distinguish two subtypes. Deterministic constraints can be verified programmatically, while semantic constraints require LLMbased judgment.

2.3.1 Deterministic Architectural Constraints. Lines 24-33 specify the layered architecture and directory structure.

through file paths or import graphs alone because they require understanding the code's intent.

Possible Violation. Consider an agent tasked with 'Persist user preferences across sessions' that discovers another component already stores related settings. Rather than defining a proper API, the agent directly reads and writes to that component's storage keys. This violates encapsulation and couples the components in ways that are difficult to detect in code review.

ContextCov handles semantic constraints using an LLM-asjudge approach, where the LLM evaluates whether code changes respect the guideline. These checks produce warnings rather than hard blocks, flagging potential violations for human review:

[ContextCov] WARNING: Possible architectural violation Rule: "MUST NOT use storage keys of another component" File: src/vs/workbench/contrib/settings/storage.ts Concern: Appears to access 'terminal.integrated.fontSize' which belongs to the terminal component. Suggestion: Define an API in the terminal component instead.

## 3 ContextCov Design

ContextCov consists of two main phases. Check generation extracts and synthesizes constraints into executable checks, and runtime enforcement executes these checks during agent operation. Given an Agent Instruction file, ContextCov generates code-based checks that can be incrementally updated as the instruction file evolves. At runtime, source and architectural checks can be enforced over an entire repository, a git diff, or just unstaged changes, while process checks are enforced during agent execution. ContextCov is implemented in Python and uses gpt-5.2-chat for all LLM-based operations including constraint refinement, intent routing, code generation, and semantic evaluation.

## 3.1 System Overview

Figure 2 presents the high-level architecture. During extraction, Agent Instruction documents are parsed into a Markdown Abstract Syntax Tree, and a path-aware algorithm traverses the tree extracting constraints as slices with their hierarchical context preserved. An LLM refines each constraint into a standalone, unambiguous statement. During synthesis, each refined constraint is classified by an intent router into one of four enforcement domains and passed to specialized code generators that produce executable Python checks. These checks are stored in a JSON file.

Possible Violation. Consider an agent tasked with 'Add a utility function for file path normalization' that faces a decision about where to place the code. The agent might place it in src/vs/workbench/common/ because that is where it will be used. However, VS Code's layered architecture requires that such utilities belong in src/vs/base/ , the foundation layer. Similarly, an agent might create a file directly under src/vs/workbench/ rather than in one of the allowed subdirectories like browser , services , contrib , or api . Such violations are easy to make when the agent is focused on completing the immediate task rather than understanding the broader architectural constraints.

ContextCov's architectural validator constructs a dependency graph and enforces the layered structure. If an agent attempts to create a file in an invalid location, it receives immediate feedback:

```
[ContextCov] Architectural violation: src/vs/workbench/myNewUtility. ts Rule: "workbench/ only allows subdirectories: browser, services, contrib, api" Suggestion: Move to appropriate subdirectory or to base/
```

More broadly, deterministic architectural violations include layer violations (dependencies crossing architectural boundaries), cyclic dependencies, and module placement errors. These can be detected through file path analysis and import graph traversal.

2.3.2 Semantic Architectural Constraints. Lines 35-38 specify a design principle where components must not directly access another component's storage keys but should instead define proper APIs for cross-component changes. Such constraints cannot be verified

This architecture provides several benefits. When Agent Instructions change, only affected constraints are re-extracted and resynthesized, enabling efficient incremental updates. Using separate code synthesis modules improves generation quality, as each expert generator is prompted with domain-appropriate patterns and examples. The multiple enforcement modules address the heterogeneity of agent actions. Process constraints require runtime interception,

The Enforcement phase executes these checks through specialized modules. A Process Interceptor uses PATH shims to intercept shell commands before execution. A Universal Static Linter uses Tree-sitter to analyze source code across multiple languages. An Architectural Validator constructs and queries dependency graphs to detect structural violations. Finally, an LLM-as-judge evaluates semantic architectural constraints that cannot be verified through static analysis alone.

Figure 2: Architecture of ContextCov. The check generation phase comprises Extraction (parsing Agent Instructions into a Markdown AST and refining constraints via LLM) and Synthesis (routing constraints to domain-specialized code generators). The Enforcement phase executes checks through a Process Interceptor, Universal Static Linter, and Architectural Validator.

<!-- image -->

source constraints require AST analysis, deterministic architectural constraints require graph reasoning, and semantic architectural constraints require LLM-based judgment.

## 3.2 Constraint Extraction

The extraction phase transforms unstructured Markdown into a set of refined, standalone constraints. This is challenging because Agent Instructions are written for human readers who naturally understand context and scope from document structure.

The Challenge of Lexical Scope. Simple approaches to Agent Instruction segmentation fail to preserve lexical scope . Consider the following excerpt:

```
# Backend ## Testing - Use pytest ## Database - Use SQLAlchemy
```

The instruction 'Use pytest' appears as a standalone bullet, but its meaning depends on its hierarchical context and applies to Backend Testing , not to the entire project or to Database operations. If we extract this constraint without its context, we might incorrectly enforce pytest usage for frontend code or database migrations.

Markdown Abstract Syntax Tree. To preserve this hierarchical context, we parse each Agent Instruction file into a tree structure. Internal nodes represent headers at various levels (H1 through H6), leaf nodes represent content blocks (paragraphs, list items, code blocks), and edges represent containment relationships. This tree structure mirrors how humans mentally organize the document when reading it.

Path-Aware Slicing. For each leaf node representing a potential constraint, we compute its header path , the ordered sequence of ancestor headers from the document root to the leaf. In the example above, 'Use pytest' has the header path [Backend, Testing] . We then use an LLM to rewrite the raw instruction into a standalone, unambiguous statement that incorporates this context, producing a refined constraint like 'For backend testing, use the pytest framework for all unit and integration tests.' This refinement step disambiguates scope and normalizes diverse phrasings into consistent constraint statements that can be enforced without additional context.

Stable Identifiers for Incrementality. To support incremental updates, we assign each constraint a stable identifier by hashing its header path and content. When a developer modifies one section of an Agent Instruction file, only constraints from that section need to be re-extracted and re-synthesized. Constraints from unmodified sections retain their identifiers and their previously generated checks remain valid. This is important for large instruction files where full re-extraction would be expensive.

## 3.3 Constraint to Check

This phase transforms refined constraints into executable Python code. Rather than using a single monolithic code generator, we route each constraint to a specialized generator based on its enforcement domain. This domain-specific approach improves code quality because each generator is optimized for its particular verification pattern.

The Intent Router. The Router classifies each constraint into one of four enforcement domains. For the Process Domain , the router extracts target binary names (e.g., npm , yarn ), the enforcement level, and the applicable scope. For the Source Domain , it identifies target programming languages, the pattern type to detect, and the severity level. For the Architectural Deterministic Domain , it determines the constraint type (dependency direction, cycle detection, or boundary enforcement) and selects an appropriate graph algorithm. For the Architectural Semantic Domain , it preserves the natural language description of the design principle for later LLM evaluation.

The router's classification is performed by the LLM, prompted with examples of each domain to improve accuracy.

Specialized Code Generators. Each domain has a specialized Expert Generator that produces Python code tailored to that domain's verification needs. The Process Expert generates code that inspects command-line arguments and environment variables, returning a verdict that determines whether the command should proceed. The Source Expert generates code using Tree-sitter bindings that constructs AST queries and traverses parse trees, returning violations with precise file and line information. The Architectural Expert generates code using NetworkX that applies graph algorithms to dependency structures, detecting cycles, layer violations, or boundary crossings.

Tree-sitter grammars are bundled for Python, TypeScript, JavaScript, Go, and Rust. This coverage addresses the most common languages in repositories with Agent Instructions, though additional languages can be added by installing the corresponding Tree-sitter packages.

Check Storage. Synthesized checks are stored in a JSON file that can be reviewed and manually edited by developers before deployment, providing a layer of human oversight over the generated checks. The listing below shows an example entry:

```
{ "constraints": { "a7f3b2...": { "domain": "PROCESS", "original_text": "NEVER use npm run compile", "refined_text": "Block npm run compile commands", "source_file": "copilot-instructions.md", "header_path": ["Validating TypeScript changes"], "enforcement_level": "block", "check_code": "def check(cmd, args, env): ..." } } }
```

This separation of synthesis from enforcement provides several advantages. It enables incremental updates where only changed constraints trigger re-synthesis. It allows developers to inspect, modify, or disable specific checks before they take effect. And it ensures fast enforcement at runtime with no LLM calls required, since all checks are pre-compiled Python code.

## 3.4 Runtime Check Enforcement

The enforcement phase executes synthesized checks through four specialized modules, each designed for a particular type of constraint.

Process Interceptor. Enforcing process constraints requires intercepting shell commands before execution. We use $PATH manipulation for its simplicity and portability. ContextCov creates a shim directory containing wrapper scripts for monitored binaries and prepends this directory to $PATH . Each monitored binary (e.g., npm , yarn , pip ) has a corresponding wrapper script:

```
#!/bin/bash # .contextcov/bin/npm exec python -m contextcov.shim npm "$@"
```

When a command is executed, the shell resolves the binary via $PATH and finds our shim first. The shim loads relevant checks from the JSON file and executes each check with the command arguments and environment. If any check fails, the shim prints an error message to stderr explaining which constraint was violated and exits with code 1, preventing the command from running. If all checks pass, the shim uses which -a to find the real binary and executes it with the original arguments, making the interception transparent to the agent.

Universal Static Linter. ContextCov uses Tree-sitter as a universal parser for source code analysis. Tree-sitter provides incremental parsing, graceful error recovery, and a uniform API across languages, making it ideal for analyzing code in diverse repositories. The linter scans source files matching configured patterns, parses each file with the appropriate grammar based on file extension, and runs all applicable checks. Each check receives the parse tree, the raw source bytes, and the file path, allowing it to construct queries, traverse the AST, and report violations with precise locations. The following example shows a generated check that detects Promise.then() usage:

```
def check(tree, source_bytes, filepath): """Check␣for␣Promise.then()␣usage.""" query = LANGUAGE.query(""" ␣␣␣␣␣␣␣␣(call_expression ␣␣␣␣␣␣␣␣␣␣function:␣(member_expression ␣␣␣␣␣␣␣␣␣␣␣␣property:␣(property_identifier)␣@method) ␣␣␣␣␣␣␣␣␣␣(#match?␣@method␣"^then$"))␣""") violations = [] for node, name in query.captures(tree.root_node): line = source_bytes[:node.start_byte].count(b'\n') + 1 violations.append(Violation(filepath, line, "Use␣async/await␣instead␣of␣.then()")) return violations
```

Architectural Validator. Deterministic architectural constraints are enforced by constructing and querying a dependency graph. The graph is built by parsing import statements using languageappropriate techniques. Python's ast module extracts import and from ... import statements, Tree-sitter queries extract import declarations and require() calls from JavaScript and TypeScript, and regex-based extraction handles Go import blocks. The resulting graph is stored as a NetworkX DiGraph where nodes represent modules and edges represent dependencies.

Architectural checks operate on this graph to detect violations such as layer crossings, cycles, or improper module placement. The following example enforces that files under src/vs/workbench/ must reside in one of the allowed subdirectories:

```
def check(graph): """Enforce␣workbench/␣subdirectory␣structure.""" allowed = {'browser', 'services', 'contrib', 'api'} violations = [] for node in graph.nodes: if node.startswith('src/vs/workbench/'): parts = node.split('/') if len (parts) > 3: subdir = parts[3] if subdir not in allowed: violations.append(ArchViolation( source=node, message=f"Must␣be␣in␣{allowed}")) return violations
```

Semantic Architectural Validator. Some architectural constraints cannot be verified through static analysis alone because they require understanding the intent behind code. For example, the constraint 'Do not use another component's storage keys, define a proper API instead' cannot be checked by examining import graphs or file paths. It requires understanding what constitutes a 'storage key,' which code belongs to which 'component,' and whether an access pattern constitutes a violation.

For these semantic constraints, we use an LLM-as-judge approach [23]. When evaluating code changes, the LLM receives the constraint text, the relevant code snippet, and surrounding context such as file path and neighboring code. The LLM then judges whether the code respects the design principle, providing a verdict and explanation. Semantic checks produce WARNING verdicts rather than hard blocks, flagging potential violations for human review while avoiding false positives from overly strict interpretation.

## 3.5 Handling Ambiguity

A key design decision is how to handle ambiguous constraints. Agent Instructions are often written informally, and the same intent

Table 1: Dataset statistics.

|   Repositories | Median Stars   |   Median Lines |   Median Words |
|----------------|----------------|----------------|----------------|
|            723 | 2,010          |             98 |            603 |

can be expressed in many ways. When a constraint like 'Use pnpm ' is encountered, should it block only explicit npm invocations, or also yarn and bun ? Should it apply globally or only in certain directories?

We adopt a fail-closed philosophy where ambiguous constraints are interpreted strictly. 'Use pnpm ' triggers blocking of npm , yarn , and bun globally, even though a human reader might interpret this more narrowly. This approach may cause false positives, but we argue this is the correct trade-off. False positives can be overridden by developers who understand the context, either by refining the Agent Instructions to be more precise or by marking specific checks as exceptions. False negatives, on the other hand, allow violations to slip through undetected, accumulating as technical debt. This philosophy aligns with security principles where, when uncertain, the system denies the action and requires explicit authorization.

## 4 Evaluation

We evaluate ContextCov on a large corpus of open-source repositories containing Agent Instruction files. Our evaluation addresses two key questions. First, can ContextCov reliably extract constraints from diverse Agent Instructions and synthesize them into valid, executable checks (RQ1)? Second, when applied to real codebases, does ContextCov detect meaningful violations that would otherwise go unnoticed (RQ2)?

## 4.1 Experimental Setup

We use a subset of the dataset from Chatlatanagulchai et al. [20], which contains 1,925 GitHub repositories with Agent Instruction files. From this dataset, we selected the top 723 repositories ranked by star count, with the highest-starred repository having 182k stars. Table 1 summarizes the dataset characteristics. All experiments used gpt-5.2-chat for LLM-based operations and ran on an Intel Xeon Platinum 8160M CPU with 754GB RAM running Rocky Linux 9.7. We used Tree-sitter [4] for AST parsing with grammars for Python, TypeScript, JavaScript, Go, and Rust.

## 4.2 RQ1. Extraction and Synthesis Quality

We evaluate how effectively ContextCov extracts constraints from Agent Instructions and synthesizes them into valid executable checks. Figure 3 visualizes the extraction pipeline flow across all 723 repositories.

A key concern with LLM-based code generation is whether the synthesized checks are syntactically valid and executable. We validated all generated checks by parsing them and checking for syntax errors. Of the 34,374 checks that require syntax validation (Source, Process, and deterministic Architectural checks), 34,373 passed validation (99.997%). Only 1 check failed due to a syntax error. Semantic Architectural checks are excluded from this count as they use natural language prompts rather than executable code. This high validity rate demonstrates that ContextCov's domain-specialized code

<!-- image -->

Figure 3: Extraction pipeline flow across 723 repositories. The pipeline processed 51,490 AST leaf nodes, extracted 48,921 non-empty segments, and synthesized 46,316 checks across four enforcement domains. Source accounts for 28%, Process for 26%, Architectural Deterministic for 20%, and Architectural Semantic for 26%.

Table 2: Violation detection statistics across all repositories.

| Domain     | Total Checks   | Checks w/ Violations   |
|------------|----------------|------------------------|
| Source     | 13,183         | 4,232 (32%)            |
| Process    | 12,080         | 3,768 (31%)            |
| Arch (det) | 9,111          | 2,605 (29%)            |
| Arch (sem) | 11,942         | 322 (3%)               |
| Total      | 46,316         | 10,927 (24%)           |

generators produce reliable, executable checks with minimal need for manual intervention. On average, each repository produces 64 executable checks after filtering and synthesis.

## 4.3 RQ2. Detection in the Wild

We evaluate ContextCov's ability to detect constraint violations in real-world repositories. In practice, ContextCov would run on code diffs as an agent makes changes, flagging violations before they are committed. For evaluation purposes, we run ContextCov against entire repositories to assess its detection capability. This approach is necessary because these repositories do not contain metadata identifying which code was contributed by agents. It is also meaningful because agents learn from existing code patterns. Any violation found in the existing codebase represents a pattern that an agent could mimic or propagate, making repository-wide analysis a proxy for the violations agents are likely to introduce.

Figure 4 shows how violations are distributed across repositories by domain. Figure 5 shows that violations follow a long-tail distribution, highlighting areas where agents are most likely to introduce drift if not guided by enforcement.

Table 2 reports violation statistics across all 723 repositories. Of the 46,316 synthesized checks, 10,927 (24%) detected at least one violation.

Overall, ContextCov detects over 500,000 violations across 723 repositories, with 81% of repositories containing at least one violation. This demonstrates that Context Drift between documented

Figure 4: Distribution of violations across repositories by domain. The distribution exhibits high variance, with some repositories having thousands of violations while others have none, reflecting diversity in Agent Instruction specificity and codebase compliance.

<!-- image -->

Figure 5: Violation concentration across checks. A small number of constraints account for the majority of violations, suggesting that certain constraint types are systematically violated across codebases.

<!-- image -->

Agent Instructions and actual code is widespread, validating the need for automated enforcement to bridge the Reality Gap.

## 5 Discussion

The shift from human-supervised to autonomous agents fundamentally changes the role of project documentation. Context Drift, where agents produce changes that violate their instructions, is not merely a technical bug but a symptom of a deeper mismatch between how we document intent and how agents consume it. We discuss the theoretical and practical implications of treating Agent Instructions as executable specifications to bridge this Reality Gap.

## 5.1 Documentation as Code

Historically, software documentation was descriptive , written for humans who use common sense to bridge the gap between outdated docs and current code. In the era of autonomous agents, documentation like AGENTS.md is prescriptive , serving as literal execution context. ContextCov forces a paradigm shift where documentation must co-evolve with the codebase. By aggressively blocking commands or flagging code that violates Agent Instructions, the tool treats ambiguity and staleness not as minor annoyances but as build-breaking defects. This effectively turns passive Markdown into a living contract between the human developer and the AI agent.

This shift has several implications. When ContextCov blocks an agent action, developers face a choice. Either the agent's action was wrong and the instructions are correct, or the instructions need updating. Both outcomes improve the repository. This creates an instruction quality feedback loop that does not exist with passive Agent Instructions. Just as code changes undergo testing, Agent Instruction changes should be tested. ContextCov enables 'instruction tests' that verify the codebase complies with Agent Instructions before merging instruction changes.

## 5.2 The Agentic Feedback Loop

Because natural language is inherently ambiguous, compiling it into strict checks will yield 'false positives, ' such as globally blocking npm when the developer only meant to block it in /backend . Instead of seeing this as a failure of the tool, we view it as a critical communication mechanism.

When an agent hits a ContextCov enforcement block, the error is fed back into its context window. This empowers the agent to reason about the failure. If the agent determines the rule was poorly scoped, it can autonomously propose a fix to the Agent Instructions. ContextCov transforms the agent from a passive consumer of documentation into an active maintainer of project specifications. Our design adopts a strict, fail-closed interpretation of documented constraints (Section 3.5). We argue that ambiguity in Agent Instructions is itself a defect. If a rule has valid exceptions, those exceptions should be specified explicitly. By blocking ambiguous cases, ContextCov forces Agent Instructions to become more precise over time, progressively narrowing the Reality Gap.

## 5.3 Executable Interpretability

A major challenge in prompt engineering is interpretability. A developer writes 'Ensure a clean architecture' but has no idea how the LLM interprets 'clean.' ContextCov addresses this by materializing the agent's understanding into readable, deterministic Python code through Tree-sitter queries and NetworkX graphs. Developers can audit the generated checks to see exactly what the agent thinks the prompt means. If the generated check is too narrow, the developer instantly knows their natural language prompt was too vague. In this sense, ContextCov acts as a prompt debugger, providing visibility into how natural language constraints are operationalized.

This interpretability enables iterative refinement. When a check produces unexpected results, developers can trace the issue to the original constraint and refine it.

## 5.4 Guardrails vs. Sandboxes

It is important to distinguish ContextCov from security sandboxes. Security mechanisms like SELinux [53], AppArmor [14], and seccomp [42] enforce mandatory access controls at the kernel level,

while container runtimes like gVisor [33] and Firecracker [10] provide process isolation. Runtime verification frameworks [21, 36, 52] monitor program execution against formal specifications. ContextCov is not designed to prevent a malicious actor from compromising a system. Rather, it is designed to prevent a well-intentioned but hallucinating agent [41] from degrading the repository. By restricting the execution environment through mechanisms like the Process Interceptor, ContextCov bounds the agent's action space, ensuring that its exploratory problem-solving stays within approved architectural and operational limits.

ContextCov assumes three trust boundaries. Agent Instructions are written by authorized maintainers, the repository is not adversarial, and generated checks run without write permissions. Process checks can only block or allow commands, and static checks are read-only AST queries. Organizations should treat AGENTS.md with the same rigor as .github/workflows/ .

## 6 Related Work

ContextCov draws on and extends several lines of prior research.

Documentation-to-Code Consistency. Prior work has studied the 'stale docs' problem [9], API documentation issues [51, 57, 58], and README files [29, 49]. Techniques detect comment-code inconsistencies [50, 55, 56] and update comments after code changes [44, 48]. Requirements traceability research [13, 34] maintains links between specifications and implementations. However, prior work focuses on descriptive documentation (docstrings, comments) for human developers. ContextCov targets prescriptive documentation (Agent Instructions) where stale docs become execution hazards since agents treat instructions literally.

Natural Language to Specifications and Linters. Research has translated natural language to formal specifications [17, 31, 47, 62]. Specification mining extracts properties from traces [11, 26, 27, 40], while learning-based approaches infer linting rules [15]. Tools like ESLint [1], Pylint [5], Semgrep [2], Infer [18], and Error Prone [7] enforce standards but require manual configuration or focus on general defects. ContextCov generates checks from Agent Instructions using domain-routed synthesis, leveraging code search techniques [25] to produce unified Python scripts operating on Tree-sitter ASTs, NetworkX graphs, and shell shims.

LLM Agents and Alignment. Research on coding agents [59, 61] has demonstrated autonomous repository navigation and issue resolution, with benchmarks like SWE-bench [38] and BigCodeBench [63] driving rapid progress. Agent alignment frameworks like Constitutional AI [16] and Guardrails [35] focus on general-purpose safety constraints, while research on jailbreaking [60] reveals vulnerabilities in instruction-following. ContextCov provides domainspecific alignment for software engineering contexts, ensuring agents adhere to project-level conventions rather than just general safety guidelines. While Constitutional AI constrains what an LLM may generate, ContextCov constrains what an agent may execute in a specific repository context.

Architectural Conformance. Tools like Sonargraph [3] detect dependency violations, while reflexion models [46] compare intended and actual architectures. Knodel and Popescu [39] survey architecture compliance checking approaches, and ArchJava [19] embeds architectural constraints directly in the programming language. These tools require architects to manually encode rules in toolspecific formats. ContextCov extracts architectural constraints from Agent Instructions that developers are already writing, lowering the barrier to architectural enforcement.

## 7 Limitations

ContextCov may flag code that does not actually violate the intended constraint. This can occur when the LLM misinterprets the natural language constraint during extraction, when the synthesized check is overly strict, or when the constraint has implicit exceptions not captured in the Agent Instructions. When false positives occur, they serve as signals for developers to refine their Agent Instruction files, enabling the generation of more appropriate checks over time.

We did not run controlled experiments with LLM agents because diffs generated by agents for specific repositories are not publicly available. While our detection results on existing codebases suggest ContextCov would prevent agent-introduced violations, a study comparing agent task success with and without ContextCov enforcement would directly demonstrate its value. Such an evaluation would require either access to proprietary agent execution logs or a large-scale study where agents are deployed on real repositories with ContextCov integration.

## 8 Conclusion

As agents take on more complex, multi-file tasks, certain classes of constraints become impractical to enforce through manual review. Style conventions, architectural boundary rules, and process workflow requirements are inherently difficult to verify by inspection. The specification that once resided in the developer's mind must be externalized to Agent Instruction files, yet these files are passive text, and without automated enforcement, Context Drift accumulates silently.

Future work could explore self-healing instructions where ContextCov suggests edits to Agent Instructions or code changes to restore compliance. Agent Instruction files could also adopt structured language features that enable deterministic check extraction without LLM involvement, improving reliability and reducing cost.

ContextCov addresses this challenge by treating Agent Instructions as executable specifications, providing automated enforcement for constraints that are difficult to monitor manually. Through hierarchical constraint extraction, domain-specialized code synthesis, and multi-layer runtime enforcement, ContextCov transforms passive instructions into active invariants that prevent agent violations. Our evaluation on 723 open-source repositories demonstrates that ContextCov successfully extracts over 46,000 executable checks with 99.997% syntax validity and detects over 500,000 violations, with 81% of repositories containing at least one violation.

As autonomous agents become standard contributors to software repositories, frameworks like ContextCov will be essential for maintaining repository integrity, bridging the Reality Gap between what agents are told to do and what they actually do.

## References

- [1] [n. d.]. Find and fix problems in your JavaScript code - ESLint - Pluggable JavaScript Linter. https://eslint . org/. Accessed: 2026-02-16.
- [3] [n. d.]. hello2morrow. https://www . hello2morrow . com/products/sonargraph. Accessed: 2026-02-16.
- [2] [n. d.]. GitHub - semgrep/semgrep: Lightweight static analysis for many languages. https://github . com/semgrep/semgrep. Accessed: 2026-02-16.
- [4] [n. d.]. Introduction - Tree-sitter. https://tree-sitter . github . io/tree-sitter/. Accessed: 2026-02-16.
- [6] [n. d.]. vscode/.github/copilot-instructions.md. https://github . com/microsoft/ vscode/blob/main/ . github/copilot-instructions . md. Accessed: 2026-02-16.
- [5] [n. d.]. pylint. https://pypi . org/project/pylint/. Accessed: 2026-02-16.
- [7] Edward Aftandilian, Raluca Sauciuc, Siddharth Priya, and Sundaresan Krishnan. 2012. Building Useful Program Analysis Tools Using an Extensible Java Compiler. In IEEE 12th International Working Conference on Source Code Analysis and Manipulation . 14-23. doi:10 . 1109/SCAM . 2012 . 28
- [9] Emad Aghajani, Csaba Nagy, Olga Vega-Márquez, Mario Linares-Vásquez, Laura Moreno, Gabriele Bavota, and Michele Lanza. 2019. Software Documentation Issues Unveiled. In Proceedings of the 41st International Conference on Software Engineering . 1199-1210. doi:10 . 1109/ICSE . 2019 . 00122
- [8] AGENTS.md. [n. d.]. AGENTS.md. https://agents . md/. Accessed: 2026-02-16.
- [10] AmazonWebServices. [n. d.]. Firecracker. https://firecracker-microvm . github . io/. Accessed: 2026-02-16.
- [12] Sharon Andrews and Mark Sheppard. 2020. Software Architecture Erosion: Impacts, Causes, and Management. International Journal of Computer Science and Security (IJCSS) 14, 2 (June 2020), 82-93. http://www . cscjournals . org/library/ manuscriptinfo . php?mc = IJCSS-1557
- [11] Glenn Ammons, Rastislav Bodík, and James R. Larus. 2002. Mining Specifications. In ACM-SIGACT Symposium on Principles of Programming Languages . https: //api . semanticscholar . org/CorpusID:13176469
- [13] Giuliano Antoniol, Gerardo Canfora, Gerardo Casazza, Andrea De Lucia, and Ettore Merlo. 2002. Recovering traceability links between code and documentation. IEEE transactions on software engineering 28, 10 (2002), 970-983.
- [15] Johannes Bader, Andrew Scott, Michael Pradel, and Satish Chandra. 2019. Getafix: Learning to Fix Bugs Automatically. arXiv:1902.06111 [cs.SE] https://arxiv . org/ abs/1902 . 06111
- [14] AppArmor. [n. d.]. AppArmor. https://apparmor . net/. Accessed: 2026-02-16.
- [16] Yuntao Bai, Saurav Kadavath, Sandipan Kundu, Amanda Askell, Jackson Kernion, Andy Jones, Anna Chen, Anna Goldie, Azalia Mirhoseini, Cameron McKinnon, Carol Chen, Catherine Olsson, Christopher Olah, Danny Hernandez, Dawn Drain, Deep Ganguli, Dustin Li, Eli Tran-Johnson, Ethan Perez, Jamie Kerr, Jared Mueller, Jeffrey Ladish, Joshua Landau, Kamal Ndousse, Kamile Lukosuite, Liane Lovitt, Michael Sellitto, Nelson Elhage, Nicholas Schiefer, Noemi Mercado, Nova DasSarma, Robert Lasenby, Robin Larson, Sam Ringer, Scott Johnston, Shauna Kravec, Sheer El Showk, Stanislav Fort, Tamera Lanham, Timothy Telleen-Lawton, Tom Conerly, Tom Henighan, Tristan Hume, Samuel R. Bowman, Zac Hatfield-Dodds, Ben Mann, Dario Amodei, Nicholas Joseph, Sam McCandlish, Tom Brown, and Jared Kaplan. 2022. Constitutional AI: Harmlessness from AI Feedback. arXiv:2212.08073 [cs.CL] https://arxiv . org/abs/2212 . 08073
- [18] Cristiano Calcagno, Dino Distefano, Jérémy Dubreil, Dominik Gabi, Pieter Hooimeijer, Martino Luca, Peter O'Hearn, Irene Papakonstantinou, Jim Purbrick, and Dulma Rodriguez. 2015. Moving Fast with Software Verification. In NASA Formal Methods . 3-11. doi:10 . 1007/978-3-319-17524-9\_1
- [17] Andrea Brunello, Angelo Montanari, and Mark Reynolds. 2019. Synthesis of LTL formulas from natural language texts: State of the art and research directions. In 26th International symposium on temporal representation and reasoning (TIME 2019) . Schloss Dagstuhl-Leibniz-Zentrum für Informatik, 17-1.
- [19] Craig Chambers and David Notkin. 2002. ArchJava: Connecting Software Architecture to Implementation. Proceedings - International Conference on Software Engineering (03 2002). doi:10 . 1145/581339 . 581365
- [21] Feng Chen and Grigore Roşu. 2007. Mop: an efficient and generic runtime verification framework. In Proceedings of the 22nd annual ACM SIGPLAN conference on Object-oriented programming systems, languages and applications . 569-588.
- [20] Worawalan Chatlatanagulchai, Hao Li, Yutaro Kashiwa, Brittany Reid, Kundjanasith Thonglek, Pattara Leelaprute, Arnon Rungsawang, Bundit Manaskasemsak, Bram Adams, Ahmed E. Hassan, and Hajimu Iida. 2025. Agent READMEs: An Empirical Study of Context Files for Agentic Coding. arXiv:2511.12884 [cs.SE] https://arxiv . org/abs/2511 . 12884
- [22] Cognition AI. [n. d.]. Devin. https://devin . ai/. Accessed: 2026-02-16.
- [24] Cursor. [n. d.]. Cursor - The AI-first Code Editor. https://cursor . sh. Accessed: 2026-02-16.
- [23] Giuseppe Crupi, Rosalia Tufano, Alejandro Velasco, Antonio Mastropaolo, Denys Poshyvanyk, and Gabriele Bavota. 2025. On the Effectiveness of LLM-as-ajudge for Code Generation and Summarization. arXiv:2507.16587 [cs.SE] https: //arxiv . org/abs/2507 . 16587
- [25] Luca Di Grazia and Michael Pradel. 2023. Code search: A survey of techniques for finding code. Comput. Surveys 55, 11 (2023), 1-31.
- [26] Michael Ernst, Jeff Perkins, Philip Guo, Stephen McCamant, Carlos Pacheco, Matthew Tschantz, and Chen Xiao. 2007. The Daikon System for Dynamic Detection of Likely Invariants. Science of Computer Programming 69 (12 2007), 35-45. doi:10 . 1016/j . scico . 2007 . 01 . 015
- [28] Cuiyun Gao, Guodong Fan, Chun Yong Chong, Shizhan Chen, Chao Liu, David Lo, Zibin Zheng, and Qing Liao. 2025. A Systematic Literature Review of Code Hallucinations in LLMs: Characterization, Mitigation Methods, Challenges, and Future Directions for Reliable AI. arXiv:2511.00776 [cs.SE] https://arxiv . org/abs/ 2511 . 00776
- [27] Mark Gabel and Zhendong Su. 2008. Symbolic mining of temporal specifications. In Proceedings of the 30th international conference on Software engineering . 51-60.
- [29] Matthew Gaughan, Kaylea Champion, Sohyeon Hwang, and Aaron Shaw. 2025. The Introduction of README and CONTRIBUTING Files in Open Source Software Development. arXiv:2502.18440 [cs.SE] https://arxiv . org/abs/2502 . 18440
- [31] Shalini Ghosh, Daniel Elenius, Wenchao Li, Patrick Lincoln, Natarajan Shankar, and Wilfried Steiner. 2016. ARSENAL: automatic requirements specification extraction from natural language. In NASA Formal Methods Symposium . Springer, 41-46.
- [30] Yilin Geng, Haonan Li, Honglin Mu, Xudong Han, Timothy Baldwin, Omri Abend, Eduard Hovy, and Lea Frermann. 2025. Control Illusion: The Failure of Instruction Hierarchies in Large Language Models. arXiv:2502.15851 [cs.CL] https://arxiv . org/abs/2502 . 15851
- [32] GitHub Next. [n. d.]. GitHub Next | Copilot Workspace. https://githubnext . com/ projects/copilot-workspace. Accessed: 2026-02-16.
- [34] Orlena CZ Gotel and CW Finkelstein. 1994. An analysis of the requirements traceability problem. In Proceedings of IEEE international conference on requirements engineering . IEEE, 94-101.
- [33] Google. [n. d.]. gVisor. https://gvisor . dev/. Accessed: 2026-02-16.
- [35] Guardrails AI. [n. d.]. Guardrails AI. https://www . guardrailsai . com/. Accessed: 2026-02-16.
- [37] Yerin Hwang, Yongil Kim, Jahyun Koo, Taegwan Kang, Hyunkyung Bae, and Kyomin Jung. 2025. LLMs can be easily Confused by Instructional Distractions. In Proceedings of the 63rd Annual Meeting of the Association for Computational Linguistics (Volume 1: Long Papers) . Association for Computational Linguistics, 19483-19496. doi:10 . 18653/v1/2025 . acl-long . 957
- [36] Klaus Havelund and Grigore Rosu. 2001. Monitoring programs using rewriting. In Proceedings 16th Annual International Conference on Automated Software Engineering (ASE 2001) . IEEE, 135-143.
- [38] Carlos E. Jimenez, John Yang, Alexander Wettig, Shunyu Yao, Kexin Pei, Ofir Press, and Karthik Narasimhan. 2024. SWE-bench: Can Language Models Resolve RealWorld GitHub Issues? arXiv:2310.06770 [cs.CL] https://arxiv . org/abs/2310 . 06770
- [40] Ted Kremenek, Paul Twohey, Godmar Back, Andrew Ng, and Dawson Engler. 2006. From uncertainty to belief: Inferring the specification within. In Proceedings of the 7th symposium on Operating systems design and implementation . 161-176.
- [39] Jens Knodel and Popescu Daniel. 2007. A Comparison of Static Architecture Compliance Checking Approaches. In 2007 Working IEEE/IFIP Conference on Software Architecture (WICSA'07) . 12. doi:10 . 1109/WICSA . 2007 . 1
- [41] Zheng Lin, Zhenxing Niu, Zhibin Wang, and Yinghui Xu. 2024. Interpreting and Mitigating Hallucination in MLLMs through Multi-agent Debate. arXiv:2407.20505 [cs.CV] https://arxiv . org/abs/2407 . 20505
- [43] Fang Liu, Yang Liu, Lin Shi, Zhen Yang, Li Zhang, Xiaoli Lian, Zhongqi Li, and Yuchi Ma. 2026. Beyond Functional Correctness: Exploring Hallucinations in LLM-Generated Code. arXiv:2404.00971 [cs.SE] https://arxiv . org/abs/2404 . 00971
- [42] Linux Kernel. [n. d.]. Seccomp BPF. https://www . kernel . org/doc/html/latest/ userspace-api/seccomp\_filter . html. Accessed: 2026-02-16.
- [44] Zhongxin Liu, Xin Xia, Meng Yan, and Shanping Li. 2020. Automating justin-time comment updating. In Proceedings of the 35th IEEE/ACM International conference on automated software engineering . 585-597.
- [46] Gail Murphy, David Notkin, and Kevin Sullivan. 2001. Software Reflexion Models: Bridging the Gap between Design and Implementation. IEEE Transactions on Software Engineering 27 (05 2001), 364-380. doi:10 . 1109/32 . 917525
- [45] Arthur-Jozsef Molnar and Simona Motogna. 2020. Long-Term Evaluation of Technical Debt in Open-Source Software. arXiv:2007.13422 [cs.SE] https:// arxiv . org/abs/2007 . 13422
- [47] Rahul Pandita, Xusheng Xiao, Hao Zhong, Tao Xie, Stephen Oney, and Amit Paradkar. 2012. Inferring method specifications from natural language API descriptions. In 2012 34th International Conference on Software Engineering (ICSE) . IEEE, 815-825.
- [49] Gede Artha Azriadi Prana, Christoph Treude, Ferdian Thung, Thushari Atapattu, and David Lo. 2018. Categorizing the Content of GitHub README Files. arXiv:1802.06997 [cs.SE] https://arxiv . org/abs/1802 . 06997
- [48] Sheena Panthaplackel, Pengyu Nie, Milos Gligoric, Junyi Jessy Li, and Raymond Mooney. 2020. Learning to update natural language comments based on code changes. In Proceedings of the 58th Annual Meeting of the Association for Computational Linguistics . 1853-1868.
- [50] Inderjot Kaur Ratol and Martin P Robillard. 2017. Detecting fragile comments. In 2017 32nd IEEE/ACM International Conference on Automated Software Engineering (ASE) . IEEE, 112-122.

- [51] Martin P Robillard and Robert DeLine. 2011. A Field Study of API Learning Obstacles. Empirical Software Engineering 16, 6 (2011), 703-732.
- [53] SELinux Project. [n. d.]. SELinux. https://selinuxproject . org/. Accessed: 2026-0216.
- [52] Runtime Verification Inc. [n. d.]. RV-Monitor. https://runtimeverification . com/. Accessed: 2026-02-16.
- [54] Freda Shi, Xinyun Chen, Kanishka Misra, Nathan Scales, David Dohan, Ed Chi, Nathanael Schärli, and Denny Zhou. 2023. Large Language Models Can Be Easily Distracted by Irrelevant Context. arXiv:2302.00093 [cs.CL] https://arxiv . org/abs/ 2302 . 00093
- [56] Shin Hwei Tan, Darko Marinov, Lin Tan, and Gary T Leavens. 2012. @tcomment: Testing javadoc comments to detect comment-code inconsistencies. In 2012 IEEE Fifth International Conference on Software Testing, Verification and Validation . IEEE, 260-269.
- [55] Lin Tan, Ding Yuan, Gopal Krishna, and Yuanyuan Zhou. 2007. /* iComment: Bugs or bad comments?*/. In Proceedings of twenty-first ACM SIGOPS symposium on Operating systems principles . 145-158.
- [57] Christoph Treude and Martin P Robillard. 2016. Augmenting API Documentation with Insights from Stack Overflow. In Proceedings of the 38th International Conference on Software Engineering . 392-403.
- [58] Gias Uddin and Martin P Robillard. 2015. How API Documentation Fails. IEEE Software 32, 4 (07 2015), 68-75. doi:10 . 1109/MS . 2014 . 80
- [59] Xingyao Wang, Boxuan Li, Yufan Song, Frank F. Xu, Xiangru Tang, Mingchen Zhuge, Jiayi Pan, Yueqi Song, Bowen Li, Jaskirat Singh, Hoang H. Tran, Fuqiang Li, Ren Ma, Mingzhang Zheng, Bill Qian, Yanjun Shao, Niklas Muennighoff, Yizhe Zhang, Binyuan Hui, Junyang Lin, Robert Brennan, Hao Peng, Heng Ji, and Graham Neubig. 2025. OpenHands: An Open Platform for AI Software Developers as Generalist Agents. arXiv:2407.16741 [cs.SE] https://arxiv . org/abs/2407 . 16741
- [61] John Yang, Carlos E. Jimenez, Alexander Wettig, Kilian Lieret, Shunyu Yao, Karthik Narasimhan, and Ofir Press. 2024. SWE-agent: Agent-Computer Interfaces Enable Automated Software Engineering. arXiv:2405.15793 [cs.SE] https://arxiv . org/abs/2405 . 15793
- [60] Zeming Wei, Yifei Wang, Ang Li, Yichuan Mo, and Yisen Wang. 2024. Jailbreak and Guard Aligned Language Models with Only Few In-Context Demonstrations. arXiv:2310.06387 [cs.LG] https://arxiv . org/abs/2310 . 06387
- [62] Hao Zhong, Lu Zhang, Tao Xie, and Hong Mei. 2009. Inferring resource specifications from natural language API documentation. In 2009 IEEE/ACM International Conference on Automated Software Engineering . IEEE, 307-318.
- [63] Terry Yue Zhuo, Minh Chien Vu, Jenny Chim, Han Hu, Wenhao Yu, Ratnadira Widyasari, Imam Nur Bani Yusuf, Haolan Zhan, Junda He, Indraneil Paul, et al. 2024. Bigcodebench: Benchmarking code generation with diverse function calls and complex instructions. arXiv preprint arXiv:2406.15877 (2024).