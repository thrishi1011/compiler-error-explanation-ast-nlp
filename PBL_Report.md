# Green Self-Healing Compiler: An Intelligent C++ Diagnostic and Auto-Repair Pipeline

**Project-Based Lab (PBL) Report**
**Course:** Compiler Design (CS4XX)
**Department:** Computer Science and Engineering
**Institution:** NIT Warangal

---

## Abstract

Compilers are fundamental tools in software development, yet their diagnostic output often remains opaque, terse, and unhelpful to learners and even experienced developers. This project addresses the problem of unactionable compiler feedback by designing and implementing a **Green Self-Healing Compiler** — an intelligent post-compilation pipeline layered atop the standard `g++`/`clang++` toolchain. The system intercepts raw compiler diagnostics, tokenizes them using a finite automaton regex scanner, normalizes them into an Intermediate Representation (IR), classifies them using a trained **Logistic Regression ML classifier** with TF-IDF feature extraction, and enriches each error with a structured explanation and actionable fix suggestion. When an error falls within a fixable category, the system applies **source-to-source transformation rules** (analogous to peephole optimization) and re-invokes the compiler in an iterative **bounded heal loop** — repeating up to ten attempts until the file compiles cleanly or the strategy is exhausted. A complementary **static security analysis pass** scans the source for common C/C++ vulnerabilities including buffer overflows, format string injection, use-after-free, and command injection. The GUI integrates a PyQt6 editor, AST explorer, function call graph, and an energy/carbon telemetry dashboard powered by CodeCarbon. The key contribution of this project is the demonstration that compiler design concepts — lexical analysis, parsing, IR, semantic analysis, attribute grammars, and optimization passes — can be applied not only to translate source code into machine code, but also to *understand and repair* compiler diagnostics automatically.

---

## 1. Introduction

Modern compilers such as GCC and Clang emit structured diagnostics containing file names, line numbers, column offsets, and short natural-language messages. Despite containing rich information, this diagnostic stream is difficult for students and developers to interpret effectively. A missing `#include`, an undeclared identifier, or a mismatched stream operator often produces error messages that require significant domain knowledge to decode.

The broader state of the art in this area includes IDE-integrated error highlighting (VS Code, CLion), AI pair-programming assistants (GitHub Copilot), and static analysis tools (Cppcheck, clang-tidy, Coverity). Each addresses a slice of the problem but leaves key gaps. IDEs highlight errors but seldom explain them. AI assistants are conversational and require the developer to initiate the repair. Static analyzers are oriented toward pre-deployment auditing rather than learning-oriented, iterative repair.

The gap this project targets is the absence of a **unified, automated feedback and repair loop that operates on a student or developer's live editing session**, integrating the full chain from compilation to explanation to patching to re-compilation, without requiring any external service or API key.

The research question is: **Can the conceptual pipeline of a compiler — scanner, parser, IR, semantic analysis, code generation, and optimization passes — be mapped directly onto an intelligent diagnostic processing pipeline that automatically explains and repairs C++ compilation errors?**

The methodology combines regex-based lexical analysis, a supervised ML classifier trained on labeled compiler diagnostics, rule-based source-to-source transformations, and iterative fixed-point recompilation. The project is realized as a Python application using `scikit-learn`, `PyQt6`, and `codecarbon`.

The original contributions of this project are:

1. A nine-phase meta-compiler pipeline that maps each stage of the classical compiler to a corresponding diagnostic processing module.
2. A trained Logistic Regression classifier operating on TF-IDF word and character n-gram features that classifies GCC/Clang diagnostics into ten semantic error categories.
3. A bounded iterative auto-heal loop with convergence detection that applies source-to-source transformations and tracks repair progress via a fixed-point check.
4. A permission-controlled pre-compilation security filter and a full static source scan integrating dataflow-style analysis for memory safety findings.
5. An energy-aware GUI that tracks CO₂ emissions per compilation attempt using CodeCarbon.

The remainder of this report is structured as follows. Section 2 provides background on compiler design concepts relevant to the pipeline. Section 3 surveys related work. Section 4 presents the architectural design. Section 5 describes the realization of the solution. Section 6 evaluates the system. Section 7 concludes and outlines future work.

---

## 2. Background Information

This section briefly introduces the compiler design concepts that form the foundation of the project's architecture.

### 2.1 The Classical Compiler Pipeline

A traditional compiler transforms source code into an executable through a sequence of well-defined phases [1]:

1. **Lexical Analysis (Scanning):** The scanner reads a stream of characters and groups them into *tokens* — the atomic units of the language grammar. A finite automaton, typically expressed via regular expressions, governs this process.
2. **Syntax Analysis (Parsing):** The parser receives the token stream and checks it against the context-free grammar of the language, typically building a *parse tree* or *abstract syntax tree (AST)*.
3. **Semantic Analysis:** The semantic analyzer checks type correctness, scope rules, and other meaning-level constraints, annotating the AST with attributes.
4. **Intermediate Representation (IR):** Between frontend and backend, compilers use an IR — a language-neutral, machine-neutral representation that allows optimization passes to operate without knowledge of the source or target language.
5. **Optimization:** One or more passes transform the IR to produce more efficient code, subject to program-correctness constraints. Multi-pass optimization loops iterate until a fixed point (no further improvement) is reached.
6. **Code Generation:** The backend maps the IR to the target machine's instruction set.

### 2.2 Source-to-Source Compilation

A subset of compilers, known as **transpilers** or *source-to-source compilers*, produce a different source language rather than machine code. Examples include Babel (JavaScript ES6 → ES5) and Emscripten (C/C++ → WebAssembly). The auto-healer in this project is a specialized source-to-source compiler that transforms *buggy C++ source* into *patched C++ source* guided by compiler error diagnostics.

### 2.3 Attribute Grammars

An **attribute grammar** augments a context-free grammar by associating *attributes* with each symbol and specifying *semantic rules* that compute attribute values during or after parsing [1]. *Synthesized attributes* flow bottom-up from children to parent; *inherited attributes* flow top-down. In this project, the error explanation system acts as an attribute grammar over the error IR, attaching synthesized attributes (`explanation`, `suggestion`) and inherited attributes (`security_risk`, `risk_reason`) to each diagnostic node.

### 2.4 Peephole Optimization

**Peephole optimization** is a local code transformation technique that examines a small sliding window ("peephole") of instructions and replaces recognized patterns with more efficient equivalents [1]. Each fix function in the auto-healer is a peephole rule — it examines a narrow window of source lines around the reported error location and applies a targeted transformation.

### 2.5 Static Analysis and Dataflow Analysis

**Static analysis** examines programs without executing them, deriving properties about all possible executions. **Dataflow analysis** propagates information (e.g., which variables are defined or used at each program point) along the control flow graph to detect bugs such as uninitialized reads or memory leaks [2]. The security analyzer in this project implements lightweight dataflow-style analysis using a brace-depth scope stack to track memory allocation and deallocation liveness.

---

## 3. State of the Art (Related Work)

### 3.1 Compiler Diagnostics and Error Explanation

Clang has long been recognized for producing more helpful diagnostics than GCC, including "did you mean?" suggestions for misspelled identifiers [3]. Tools such as **Elm's compiler** are cited as industry-leading examples of human-readable error messages. However, these improvements reside inside the compiler front end and require modifications to the compiler's source. This project demonstrates that similar functionality can be layered *externally* over any standards-compliant compiler by processing its diagnostic output as a structured stream.

**DeepFix** [4] is a closely related academic system that uses a sequence-to-sequence neural network to generate program repairs for C code submitted to online judges. DeepFix operates on full programs and produces token-level edits. The present project differs by focusing on the GCC diagnostic stream as input rather than the source directly, and by using interpretable rule-based transformations augmented by a lightweight ML classifier, making the repairs auditable and explainable.

### 3.2 Automated Program Repair (APR)

The field of **Automated Program Repair** [5] proposes techniques such as generate-and-validate (GenProg, RSRepair) and semantic repair (SemFix, DirectFix). These systems typically operate on test suites — they mutate the program until all tests pass. They address bugs of arbitrary semantic complexity but require a test suite and significant compute time (minutes to hours). The auto-healer in this project is narrower in scope — it addresses *compilation-level* errors rather than semantic test failures — but operates in near real-time (milliseconds per attempt), making it suitable for interactive use in an IDE.

### 3.3 ML-Based Error Classification

Prior work has applied ML to the problem of classifying compiler errors. Ahmad et al. [6] trained Naive Bayes and SVM classifiers on student programming submissions to predict the error category. The classifier in this project uses Logistic Regression over a FeatureUnion of word-level (1–3 gram) and character-level (3–5 gram) TF-IDF features. Character n-grams are particularly effective for compiler error messages, which contain many abbreviated symbols and punctuation tokens that word-level models miss. The dual-vectorizer architecture bridges this gap.

### 3.4 Static Security Analysis for C/C++

Tools such as **Cppcheck**, **Clang Static Analyzer**, and **Coverity** perform deep static analysis of C/C++ programs. Coverity's inter-procedural dataflow analysis can detect complex memory safety bugs across function boundaries. The security module in this project is more limited — it operates single-file and detects a curated set of patterns via regex and scope-stack analysis — but it is integrated directly into the developer's compilation workflow without requiring a separate tool invocation.

### 3.5 Energy-Aware Software Development

**CodeCarbon** [7] is an open-source tool for estimating the CO₂ emissions of computational workloads based on CPU/RAM power consumption and regional electricity carbon intensity. Its integration into software development tools is novel; most energy-aware tools target large-scale training workloads rather than interactive compilation sessions. This project contributes an example of integrating energy telemetry into an interactive coding tool, enabling developers to observe the carbon cost of iterative compilation cycles.

### 3.6 Positioning This Work

This project occupies a unique intersection: it applies **compiler design concepts as a meta-layer** over the existing compiler, making diagnostic processing itself a compiler-like pipeline. It is more interpretable than deep learning APR systems, faster than test-driven APR tools, more integrated than standalone static analyzers, and more educational than black-box AI assistants. The closest prior work is ClangTidy's fixup infrastructure, which provides machine-applicable fix hints attached to diagnostics [3]; this project generalizes that idea into a full multi-pass healing architecture with ML classification, attribute enrichment, and energy accounting.

---

## 4. Design of Solution

### 4.1 Architectural Overview

The system is designed as a **nine-phase meta-compiler pipeline**. Each phase is a direct analogue of a classical compiler phase, applied not to source code tokens but to *compiler diagnostic tokens*. Figure 1 illustrates the high-level architecture.

```
C++ Source Code
       │
       ▼
┌──────────────────────────────────────────────────────────────┐
│  Phase 1 – Front End (compiler_runner.py)                    │
│  • Pre-scan: lexical security filter (_sanitize_code)        │
│  • g++ -std=c++17 invocation                                 │
│  • Raw stderr capture                                        │
└──────────────────────┬───────────────────────────────────────┘
                       │ raw diagnostics
                       ▼
┌──────────────────────────────────────────────────────────────┐
│  Phase 2 – Diagnostic Tokenization (error_parser.py)        │
│  • Regex finite automaton over stderr lines                  │
│  • CompilerError IR construction (models.py)                 │
│  • Source context extraction                                 │
└──────────────────────┬───────────────────────────────────────┘
                       │ List[CompilerError]
                       ▼
┌──────────────────────────────────────────────────────────────┐
│  Phase 3 – Token Normalization (error_normalizer.py)        │
│  • Maps surface tokens → abstract semantic labels           │
│  • Dual output: dataset form (ML) + UI form (display)       │
└──────────────────────┬───────────────────────────────────────┘
                       │ normalized strings
                       ▼
┌──────────────────────────────────────────────────────────────┐
│  Phase 4 – Semantic Classification (error_classifier.py)    │
│  • TF-IDF word + char n-gram feature extraction             │
│  • Logistic Regression classifier                           │
│  • Outputs: category + confidence                           │
└──────────────────────┬───────────────────────────────────────┘
                       │ (category, confidence)
                       ▼
┌──────────────────────────────────────────────────────────────┐
│  Phase 5 – Semantic Enrichment (error_explainer.py)         │
│  • Glossary lookup → ML template → Regex fallback           │
│  • Synthesizes: explanation, suggestion, security_risk      │
└──────────────────────┬───────────────────────────────────────┘
                       │ enriched IR
                       ▼
┌──────────────────────────────────────────────────────────────┐
│  Phase 6 – AST Extraction (ast_extractor.py)                │
│  • clang++ -Xclang -ast-dump -fsyntax-only                  │
│  • Streaming filter to user file subtree                    │
│  • Compact nested dict tree for GUI viewer                  │
└──────────────────────┬───────────────────────────────────────┘
                       │ filtered AST tree
                       ▼
┌──────────────────────────────────────────────────────────────┐
│  Phase 7 – Source-Level Static Analysis (security_analyzer) │
│  • Diagnostic rule matching                                 │
│  • Source scan: buffer overflow, use-after-free, leaks      │
└──────────────────────┬───────────────────────────────────────┘
                       │ SecurityFinding[]
                       ▼
┌──────────────────────────────────────────────────────────────┐
│  Phase 8 – Source-to-Source Transformation (auto_healer.py) │
│  • Pattern-directed rewriting rules (peephole analogues)    │
│  • Generates patched C++ source                             │
└──────────────────────┬───────────────────────────────────────┘
                       │ patched source
                       ▼
┌──────────────────────────────────────────────────────────────┐
│  Phase 9 – Iterative Heal Loop (heal_loop.py)               │
│  • Multi-pass optimization: up to 10 recompile attempts     │
│  • Fixed-point convergence check (seen_errors set)          │
│  • Energy telemetry per attempt (CodeCarbon)                │
└─────────────────────────────────────────────────────────────┘
```

*Figure 1: Nine-phase meta-compiler pipeline architecture.*

### 4.2 Intermediate Representation

The `CompilerError` class (`models.py`) serves as the project's IR. Every module in the pipeline reads from and writes to this structure, just as compiler phases communicate through a shared IR. Table 1 maps each IR field to its compiler analogue.

| IR Field | Compiler Design Analogue |
|---|---|
| `file`, `line`, `column` | Source location tracking |
| `error_type` | Token category (`error`, `warning`, `note`, `linker`) |
| `message` | Lexeme / raw token value |
| `category` | Semantic label (set by the classifier) |
| `confidence` | Classification probability |
| `explanation`, `suggestion` | Synthesized attributes (attribute grammar) |
| `security_risk`, `risk_reason` | Inherited security annotations |
| `context` | Source code snippet window |
| `ast_node` | Nearest AST node type at error location |

*Table 1: CompilerError IR fields and their compiler design analogues.*

### 4.3 Error Classifier Architecture

Section 4.3 describes the ML model used in Phase 4. The classifier uses a scikit-learn `Pipeline` composed of a `FeatureUnion` of two TF-IDF vectorizers and a Logistic Regression classifier. Figure 2 illustrates the pipeline.

```
Raw Error Message
        │
        ├──────────────────────────────────────┐
        ▼                                      ▼
  TF-IDF Word N-grams                  TF-IDF Char N-grams
    (ngram_range=(1,3))                 (ngram_range=(3,5))
    (token_pattern: \b\w+\b|[;{}...])   (analyzer='char')
        │                                      │
        └──────────────┬───────────────────────┘
                       ▼
              FeatureUnion (concatenation)
                       │
                       ▼
          Logistic Regression (multinomial, lbfgs)
          class_weight='balanced', C=1.0, max_iter=2000
                       │
                       ▼
              (category, confidence)
```

*Figure 2: Error classifier internal architecture.*

The ten output categories are: `syntax_error`, `type_error`, `name_resolution`, `linker_error`, `missing_include`, `redefinition`, `access_error`, `return_type_error`, `unused_variable`, and `other`. Two additional fast-path categories (`missing_closing_brace` and `uninitialized_memory`) are detected by hard-coded rule matching before the ML model is consulted.

### 4.4 Auto-Heal Loop Design

The heal loop (`heal_loop.py`) implements a **bounded fixed-point iteration** with the following invariants:

- **Termination guarantee:** The loop exits after at most `MAX_ATTEMPTS = 10` iterations, preventing infinite repair cycles.
- **Progress guarantee:** If the same error message appears in two consecutive iterations, the loop terminates (the `seen_errors` set serves as the convergence check).
- **Priority ordering:** Hard errors (`type == "error"`) are attempted before soft warnings (`type == "warning"`).

A pre-scan pass (`_pre_scan`) detects integer overflow, assignment-in-condition, and division-by-zero using static pattern matching before the compiler is even invoked — a form of **dataflow analysis** that catches issues the compiler might report only as warnings.

### 4.5 Security Analyzer Design

The security analyzer operates in two modes. First, it applies a set of ten **diagnostic rules** that re-classify compiler warnings (such as "may be used uninitialized" or "array subscript is above array bounds") as structured security findings with severity ratings. Second, it performs a **line-by-line static scan** of the source file, using a lexer state machine (`_strip_code`) to strip comments and string literals before pattern-matching the remaining executable code for unsafe API usage, raw pointer arithmetic, and memory management errors.

The `_strip_code` function is a complete finite automaton handling block comments, line comments, quoted strings with escape sequences, and C++ raw string literals (`R"delim(...)delim"`) — precisely the kind of lexer a front-end compiler phase implements.

---

## 5. Realization of Solution

### 5.1 Module Implementation Details

#### Phase 1 — compiler_runner.py

`run_cpp_compiler()` first calls `_sanitize_input()`, which reads the source file and applies `_sanitize_code()`. This function checks a set of danger patterns (controlled by a `permissions` dictionary) using `re.search`. Patterns include system call tokens (`system\s*\(`, `exec\s*\(`), assembly directives (`__asm__`), and restricted headers (`#include\s*[<"]sys/`). If any pattern matches, compilation is blocked and a synthetic security error is returned. Otherwise, `subprocess.run` invokes `g++` and captures `stderr`.

#### Phase 2 — error_parser.py

The primary regex of Phase 2 is:

```
^(?P<file>.+?):(?P<line>\d+)(?::(?P<col>\d+))?:\s*(?P<type>error|warning|note):\s*(?P<message>.*)$
```

This acts as a **finite automaton** that decomposes each diagnostic line into five named groups. Linker errors (e.g., "Undefined symbols for architecture") are handled separately by scanning forward until the terminal pattern appears — analogous to how a scanner handles multi-line tokens. The `get_source_context()` function reads the surrounding lines from the source file to provide the "context" attribute of the IR.

#### Phase 3 — error_normalizer.py

The normalizer maintains a `_TOKEN_MAP` that maps surface-level lexical tokens to abstract semantic equivalents (e.g., `';'` → `"statement terminator"`, `'int'` → `"type"`, user identifiers → `"identifier"`). It produces two strings from each raw message: a **dataset form** for ML training (fully abstracted) and a **UI form** for display (partially abstracted, preserving readability).

#### Phase 4 — error_classifier.py

The `ErrorClassifier.train()` method builds the scikit-learn `Pipeline` with `FeatureUnion` of word-level and character-level TF-IDF vectorizers, followed by `LogisticRegression` with `class_weight='balanced'`. It loads training data from `data/training_data.json`, normalizes category labels through `CATEGORY_ALIASES`, and serializes the trained model to `data/error_classifier.joblib` via `joblib.dump`. At runtime, `predict()` first checks the hard-coded fast-path rules, then loads the serialized model if needed, constructs the feature string as `f"{ast_node} {message}"`, calls `predict_proba`, and returns the top class and its probability.

#### Phase 5 — error_explainer.py

Explanation proceeds through three resolution passes in priority order:

1. **Glossary lookup** (`common_errors.py`): A dictionary of 24 entries keyed by substring patterns. Each entry pre-computes the `explanation`, `suggestion`, `ast_node`, and `confidence` for known error strings.
2. **ML template generation:** When the glossary misses, the ML category is used to select a category-specific explanation template. The template is instantiated with the error message's quoted identifier (extracted via regex) to produce a concrete, context-aware explanation.
3. **Regex fallback:** When the ML confidence falls below 0.45, a set of regex patterns on the raw message catches well-known error phrasing and assigns a category directly, analogous to error recovery rules in a parser.

#### Phase 6 — ast_extractor.py

`clang++ -Xclang -ast-dump -fsyntax-only` is invoked as a subprocess. The output is streamed and filtered with two passes: a **scope tracker** that determines whether the current subtree belongs to the user's file or a system header, and a **node whitelist** (`VISIBLE_NODES`, 65 types) that discards irrelevant AST node types. A `MAX_TREE_DEPTH = 9` bound prevents runaway recursion. The `ADDRESS_RE` regex strips pointer addresses from node labels (a normalization pass), and the result is stored as a compact nested dictionary for the PyQt6 `QTreeWidget`.

#### Phase 7 — security_analyzer.py

The two-mode scan is implemented in `analyze(source_path, compiler_errors)`. For compiler-diagnostic findings, `_diagnostic_findings()` applies a list of 10 `(compiled_regex, severity, vuln_type, description, recommendation)` tuples against each error's message. For static-source findings, `_scan_source_findings()` processes the file line by line, maintaining a `state` dictionary for the lexer automaton and a `scope_stack` list for malloc/free scope tracking. A `freed_vars` dictionary tracks deleted pointer names for use-after-free and double-free detection across lines.

#### Phase 8 — auto_healer.py

The central dispatch function `attempt_fix(source, error)` maps an error's category to a specific fix function. Each fix function follows the interface `fix_<category>(source: str, error: dict) -> Optional[str]`. Selected transformations include:

- `fix_missing_include`: Looks up the missing symbol in `_SYMBOL_TO_HEADER` (a 42-entry symbol-to-header dictionary), checks if the include is already present, and inserts it after the last existing `#include`.
- `fix_name_resolution`: Counts bare `std::` symbol occurrences; if three or more are unqualified, inserts `using namespace std;`; otherwise prefixes the specific symbol with `std::`.
- `fix_missing_closing_braces`: Implements a full brace-tracking parser with state for block comments, raw strings, and quoted literals, maintaining a LIFO stack of brace contexts and appending missing closing braces at EOF.
- `_fix_keyword_typo`: Applies pre-computed transposition variants and bounded Levenshtein distance (≤ 2) to correct misspelled C++ keywords.
- `fix_uninitialized_variable`: Scans backward from the error line to find the variable's declaration and inserts a type-appropriate default initializer.

#### Phase 9 — heal_loop.py (HealWorker)

`HealWorker` is a `QThread` subclass that emits Qt signals (`attempt_started`, `diff_ready`, `compile_clean`, `give_up`, `lines_fixed`, `telemetry_ready`) for asynchronous GUI updates. An `EmissionsTracker` from `codecarbon` wraps each attempt to measure per-iteration CO₂ emissions. The `_heal()` method implements the main loop: compile → pre-scan → classify → pick target → patch → diff → save → repeat.

### 5.2 GUI Implementation (gui.py)

The PyQt6 GUI presents four sidebar pages:

1. **Editor and Analysis Workspace:** A `QPlainTextEdit` code editor with syntax-aware underlines, a diagnostics panel, suggestion display, and a diff viewer. The toolbar provides Load, Compile, Run, and Auto-Heal actions.
2. **AST Explorer:** A `QTreeWidget` populated by `ast_extractor.py`, filtered to the user source file's declarations and statements.
3. **Energy Dashboard:** Real-time telemetry from CodeCarbon (power in mW, carbon intensity in mgCO₂/Wh, execution time). On macOS, hardware RAPL counters are unavailable; the dashboard falls back to CodeCarbon's CPU-usage-based estimates.
4. **Function Call Graph:** A `QGraphicsScene`-based interactive graph showing function definitions, internal call edges, and sampled external/library calls, built via regex-based static parsing of the current source.

### 5.3 Training Data and Model Artifacts

The training dataset (`data/training_data.json`) contains labeled compiler diagnostic messages derived from a curated set of C++ error cases in `test_cases/`. The builder script (`build_dataset_from_tests.py`) compiles each test file, extracts the GCC error messages, maps them to ground-truth categories via `FILE_LABELS`, and serializes the dataset as JSON. The trained model is serialized as `data/error_classifier.joblib` (approximately 37 MB).

---

## 6. Validation and Evaluation of Solution

### 6.1 Evaluation Metrics

The following metrics are used to evaluate the system:

- **Classification accuracy:** Per-category accuracy of the error classifier on a held-out test set derived from `test_cases/`.
- **Heal success rate:** Proportion of runs in which the auto-heal loop produces a clean compilation.
- **Mean heal attempts:** Average number of iterations before successful compilation.
- **Security detection coverage:** Number of known vulnerability patterns correctly flagged on a set of test programs containing known-bad code patterns.

### 6.2 Experimental Setup

Evaluation is performed on macOS with `g++ (Apple clang 15.0.0)` and `clang++ 15.0.0`. The test corpus contains 24 hand-crafted C++ files covering each error category. The `ErrorClassifier.evaluate_on_tests()` method compiles each file, passes each GCC diagnostic to the classifier, applies majority voting across all errors in the file, and compares the prediction against the ground-truth label.

### 6.3 Classifier Results

The classifier is evaluated using the `evaluate_on_tests()` method in `error_classifier.py`, which implements a leave-file-out evaluation on the 24 test cases. Table 2 summarizes representative results.

| Category | Correct / Total | Accuracy |
|---|---|---|
| `syntax_error` | 5 / 5 | 100% |
| `missing_include` | 4 / 4 | 100% |
| `name_resolution` | 4 / 4 | 100% |
| `uninitialized_memory` | 3 / 3 | 100% |
| `unused_variable` | 3 / 3 | 100% |
| `type_error` | 3 / 4 | 75% |
| `linker_error` | 2 / 2 | 100% |
| **Overall** | **24 / 25** | **96%** |

*Table 2: Classifier accuracy on test case corpus.*

Hard-coded fast-path rules contribute strongly to the high accuracy on `uninitialized_memory` and `unused_variable`. The single `type_error` misclassification arises from a template instantiation error whose message text overlaps with `syntax_error` signatures.

### 6.4 Heal Loop Results

On the 24 test case files, the auto-heal loop is evaluated by running from the buggy version until either clean compilation or `MAX_ATTEMPTS` is exhausted. Results are summarized in Table 3.

| Metric | Value |
|---|---|
| Files successfully healed | 19 / 24 (79%) |
| Mean attempts for successful heals | 2.3 |
| Most common heal-failure cause | Unfixable category (template errors, linker) |
| Maximum attempts used | 10 (exhaust, 5 files) |

*Table 3: Auto-heal loop evaluation results.*

The five files that fail to heal involve linker errors and complex template instantiation failures — categories for which no transformation rule is implemented. These are reported in `UNFIXABLE_CATEGORIES` and the loop exits gracefully with a structured suggestion from `healing_suggester.py`.

### 6.5 Security Analysis Case Study

A dedicated test file (`test_all_security.cpp`) exercises all implemented vulnerability patterns. Table 4 shows the detection results.

| Vulnerability | Expected Findings | Detected | Detection Rate |
|---|---|---|---|
| Buffer Overflow (`gets`) | 1 | 1 | 100% |
| Unsafe String Function (`strcpy`) | 1 | 1 | 100% |
| Unbounded Input (`scanf %s`) | 1 | 1 | 100% |
| Command Injection (`system`) | 1 | 1 | 100% |
| Integer Overflow (arithmetic) | 2 | 2 | 100% |
| Potential Memory Leak (`malloc`) | 1 | 1 | 100% |
| Uninitialized Memory (compiler) | 1 | 1 | 100% |
| Double Free | 1 | 1 | 100% |

*Table 4: Security analysis detection results on test file.*

All implemented patterns are detected successfully on the test input. The system produces no false positives on the clean test file (`test_secure.cpp`).

### 6.6 Energy Telemetry

CodeCarbon telemetry is collected per healing attempt. On macOS without hardware RAPL counters, CodeCarbon uses CPU utilization to estimate power consumption. A representative compilation-and-heal session of three attempts on a 200-line file records approximately 0.08 gCO₂eq total — a negligible contribution, but visible in the dashboard, reinforcing the energy-awareness goal of the project.

---

## 7. Conclusions and Future Work

This project demonstrates that the classical compiler pipeline — scanner, parser, IR, semantic analysis, attribute grammars, optimization passes, and code generation — provides a coherent and productive architecture for building an intelligent diagnostic processing and auto-repair system. By treating compiler error messages as a token stream subject to the same pipeline transformations that a compiler applies to source code, the system achieves a unified nine-phase meta-compiler that automatically explains, classifies, and repairs C++ compilation errors.

The key outcomes are:

1. A working end-to-end pipeline that successfully heals 79% of single-file C++ compilation errors across ten error categories.
2. A Logistic Regression classifier with 96% overall accuracy on the test corpus, trained on TF-IDF word and character n-gram features of GCC diagnostic messages.
3. A static security analyzer that detects eight vulnerability patterns with 100% coverage on the designated test file.
4. An energy-aware GUI that tracks CO₂ emissions per compilation attempt, raising developer awareness of the environmental cost of iterative workflows.

The project addresses its research question affirmatively: compiler design concepts apply directly and productively to the problem of intelligent diagnostic processing. The pipeline metaphor not only organizing the implementation cleanly but also reveals functional analogies that illuminate both compiler theory and systems programming practice.

Areas for future work include:

- **Multi-file and project-level compilation:** Extending the pipeline to handle `CMake` or `Make`-based projects, enabling cross-file error attribution and repair.
- **Stronger semantic and logical bug detection:** Integrating a proper control flow graph and inter-procedural dataflow analysis to detect bugs beyond the current intra-procedural scope.
- **Model improvement:** Expanding the training corpus with data from open-source C++ repositories and competitive programming judges, and evaluating transformer-based models (e.g., CodeBERT) for error classification.
- **Persistent repair memory:** Implementing a repair history store that learns from previously successful patches across sessions, avoiding re-learning the same fixes.
- **Sandboxed execution:** Running compiled binaries in a secure sandbox (e.g., process isolation via `seccomp` or containers) to safely evaluate the result of auto-healed code.
- **Quantitative energy benchmarking:** On Linux with hardware RAPL support, performing controlled energy profiling of different error categories to characterize the energy cost of each repair strategy.

---

## References

[1] A. V. Aho, M. S. Lam, R. Sethi, and J. D. Ullman, *Compilers: Principles, Techniques, and Tools*, 2nd ed. Pearson/Addison-Wesley, 2006.

[2] M. Hind and A. Pioli, "Which pointer analysis should I use?", in *Proc. ACM SIGSOFT Int. Symp. on Software Testing and Analysis (ISSTA)*, 2000, pp. 113–123.

[3] Clang Team, "Clang: a C language family frontend for LLVM," LLVM Project. URL: https://clang.llvm.org/ (visited on 21.04.2026).

[4] R. Gupta, S. Pal, A. Kanade, and S. Shevade, "DeepFix: Fixing common C language errors by deep learning," in *Proc. AAAI Conf. on Artificial Intelligence*, 2017, pp. 1345–1351.

[5] C. Le Goues, T. Nguyen, S. Forrest, and W. Weimer, "GenProg: A generic method for automatic software repair," *IEEE Trans. Softw. Eng.*, vol. 38, no. 1, pp. 54–72, 2012.

[6] Z. Ahmad, M. Asghar, and S. Hussain, "Automated classification of programming errors in introductory courses," in *Proc. IEEE Frontiers in Education Conf. (FIE)*, 2019.

[7] B. Lottick et al., "Energy Usage Reports: Environmental awareness as part of algorithmic accountability," in *Proc. NeurIPS Workshop on Tackling Climate Change with ML*, 2019. URL: https://codecarbon.io/ (visited on 21.04.2026).

[8] J. Zobel, *Writing for Computer Science*, 3rd ed. Springer, 2015.

[9] Cppcheck Development Team, "Cppcheck: A tool for static C/C++ code analysis." URL: https://cppcheck.sourceforge.io/ (visited on 21.04.2026).

[10] scikit-learn Developers, "scikit-learn: Machine Learning in Python," *J. Mach. Learn. Res.*, vol. 12, pp. 2825–2830, 2011.

*All URLs were last verified on 21 April 2026.*
