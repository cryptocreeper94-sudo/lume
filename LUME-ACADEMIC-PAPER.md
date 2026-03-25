# LUME: Eliminating Cognitive Distance — An AI-Native Programming Language with Natural Language Compilation, Voice Input, and Certified Security

**Author:** Jason Andrews

**Affiliation:** DarkWave Studios LLC / Trust Layer Ecosystem
DarkWave Systems Collective (DWSC) — Research & Engineering Division — team@dwsc.io

**Contact:** lume-lang.com | lume-lang.org | dwtl.io

**Keywords:** programming languages, natural language processing, voice-to-code, compiler security, cognitive distance, intent resolution, AI-native computation, accessibility

---

## Abstract

We present Lume, an AI-native programming language whose compiler is architected from the ground up to accept imprecise, informal, and ambiguous natural language as valid source code. Unlike all existing programming languages, which require exact syntactic conformity, Lume's compilation pipeline employs a seven-layer Tolerance Chain that progressively resolves developer intent from plain English text — or spoken voice — into a typed Abstract Syntax Tree (AST), which then transpiles to standard JavaScript. This architectural decision yields three capabilities that emerge as structural consequences rather than bolt-on features: (1) voice-to-code as a native compiler feature, not an IDE plugin; (2) intent-aware, AST-level security scanning that produces tamper-evident certificates embedded in compiled output — a paradigm we term "certified at birth"; and (3) near-zero cognitive distance between developer intent and compiled code, eliminating the cognitive dissonance that characterizes the daily experience of programming. We describe the language design across 13 compiler milestones, the voice-to-code pipeline architecture, the three-layer security model including the novel Guardian Output Scanner, 15 gap resolutions addressing real-world compilation challenges, and the theoretical framework connecting cognitive distance to the psychological phenomenon of cognitive dissonance. We argue that Lume represents a fundamental shift in compiler design philosophy — from rejecting imperfect input to resolving imperfect intent — with implications for accessibility, security, and the future of human-computer interaction in software development.

---

## 1. Introduction

### 1.1 The Syntax Barrier

All mainstream programming languages — Python, JavaScript, Rust, C++, Java, Go, TypeScript, and hundreds more — share a foundational assumption: the developer must express intent in exact syntactic conformity with a formal grammar. A single missing semicolon, mismatched bracket, misspelled keyword, or incorrect operator breaks compilation entirely. The compiler's role, in this paradigm, is to verify conformity and reject nonconformity.

This assumption has been unchallenged since the earliest compilers of the 1950s. It produces a phenomenon we term **cognitive distance** — the mental gap between what a developer intends and what they must type to express that intent in conformant syntax.

### 1.2 Cognitive Distance and Cognitive Dissonance

The term "cognitive distance" is deliberately chosen for its proximity to **cognitive dissonance** — the well-documented psychological phenomenon describing the mental discomfort of holding contradictory beliefs or performing actions that conflict with one's self-concept (Festinger, 1957). In the context of programming, cognitive dissonance manifests as a daily, recurring experience:

- A developer **thinks** in natural language: *"get the user's name from the database"*
- The developer is **forced to act** in a completely different language: `const name = await db.query("SELECT name FROM users WHERE id = ?", [userId])`
- The thought and the action do not match
- This mismatch occurs hundreds of times per day for every working developer

This is not metaphor — it is the literal psychological experience of programming. Every developer who has said "I know what I want to do, I just can't figure out how to write it" is describing cognitive dissonance caused by cognitive distance.

**Cognitive distance** is the quantification of that dissonance. The entire history of programming languages can be understood as an incremental effort to reduce cognitive distance:

| Era | Language/Tool | Cognitive Distance | Expression Gap |
|-----|-------------|-------------------|----------------|
| 1950s | Assembly | Maximum | "Add two numbers" → `MOV AX, 5 / ADD AX, 3` |
| 1970s | C | High | "Add two numbers" → `int result = a + b;` |
| 1990s | Python | Medium | "Add two numbers" → `result = a + b` |
| 2020s | AI Agents | Medium-High* | "Add two numbers" → ask AI → review → run |
| 2026 | Lume (text) | Near-Zero | "Add two numbers" → `add two numbers` |
| 2026 | Lume (voice) | Approaching Zero | Think → say → compiled |

*A critical observation: AI coding agents (GitHub Copilot, ChatGPT, etc.) actually **increased** the number of translation layers. Developers previously wrote code and the compiler ran it (2 layers: human → compiler). With AI agents, developers ask an AI to write code, review what it wrote, then the compiler runs it (3 layers: human → AI → compiler). The AI is a middleman. Lume eliminates the middleman — the compiler **is** the understanding layer.

### 1.3 The Thesis

We advance the following thesis: if a programming language is designed from the ground up to accept imprecise natural language as valid source code, then three capabilities emerge as architectural consequences rather than bolt-on features:

1. **Voice-to-code** — because the compiler already handles imprecise input, voice transcription noise is absorbed by the same error tolerance mechanisms
2. **Intent-aware security scanning** — because the compiler understands what the developer *meant*, not just what code was generated, security analysis operates on semantic intent rather than syntactic patterns
3. **Near-zero cognitive distance** — because the developer expresses intent in the same language they think in, the dissonance disappears

Lume is the realization of this thesis. The dissonance disappears when the distance approaches zero.

### 1.4 Contributions

This paper makes the following contributions:

1. **The Lume programming language** — a complete language specification spanning 13 milestones, from core syntax through a self-sustaining runtime to voice-to-code and zero-dependency executables, with 305 formally specified acceptance criteria
2. **The Tolerance Chain** — a 7-layer progressive fallback resolution system that transforms imprecise natural language input into typed AST nodes, maintaining deterministic reproducibility through compile-lock files
3. **The Guardian Output Scanner** — a novel security architecture that performs live, intent-aware scanning at AST node creation time during compilation, producing tamper-evident security certificates — "certified at birth"
4. **The Transcription Cleanup Layer** — a 7-step preprocessing pipeline that normalizes speech-to-text artifacts (homophones, fillers, stuttering, run-on sentences, spoken punctuation) into clean text indistinguishable from typed input
5. **15 gap resolutions** — systematic solutions to architectural challenges in natural language compilation, including ambiguity ceilings, complex boolean logic, cross-file module resolution, canonical normalization, and concurrent async patterns
6. **The cognitive distance framework** — a theoretical contribution connecting programming language design to cognitive psychology, with implications for accessibility and human-computer interaction

### 1.5 Paper Organization

Section 2 presents background and related work. Section 3 describes the core language design. Section 4 details the English Mode compilation pipeline. Section 5 presents the voice-to-code architecture. Section 6 describes the three-layer security model. Section 7 covers the self-sustaining runtime. Section 8 presents the gap resolutions. Section 9 describes advanced milestones (multilingual, visual, collaborative, executable). Section 10 discusses implementation metrics and evaluation. Section 11 presents theoretical contributions. Section 12 discusses limitations and future work. Section 13 concludes.

---

## 2. Background and Related Work

### 2.1 Natural Language Programming

The idea of programming in natural language has a long history, dating to early AI research. Systems like SHRDLU (Winograd, 1972) demonstrated natural language understanding in constrained domains. More recently, NLP-to-code systems leveraging large language models (LLMs) — including OpenAI Codex, AlphaCode, and StarCoder — have demonstrated impressive code generation from natural language prompts. However, these systems function as code generators, not compilers. They produce code that must then be reviewed, tested, and compiled separately. The LLM is a middleman, not a compiler component.

Lume differs fundamentally: natural language is not used to *generate* code that a traditional compiler processes — natural language *is* the source code that the Lume compiler directly resolves into an AST.

### 2.2 Voice-to-Code Systems

Several systems enable voice-based programming:

| System | Approach | Limitation |
|--------|----------|------------|
| **Talon** | Voice commands mapped to IDE actions | Editor-level, not language-level; rigid command grammar |
| **Serenade** | Voice-to-code templates for Python/JS | Template-based; cannot handle arbitrary phrasing |
| **GitHub Copilot Voice** | LLM-generated code from voice | Non-deterministic; no security guarantees; adds translation layer |
| **Apple Dictation / Dragon** | General speech-to-text | No programming-domain awareness whatsoever |
| **Scratch / Blockly** | Visual programming for beginners | Block-based, not voice-based; limited expressiveness |

All existing voice coding tools operate at the IDE level — they map voice commands to editor actions or code templates. The compiler itself never sees voice input. Lume is the first system where voice input flows through the compiler's own pipeline, and the compiler is architecturally designed to handle the noise that voice input introduces.

### 2.3 Compiler Security

Security analysis in traditional programming is always external to the compiler:

- **ESLint**, **SonarQube**, **Snyk**, **Semgrep** — operate post-compilation on generated code
- No access to developer intent — scan syntax patterns, not semantic meaning
- Must be installed, configured, and maintained separately
- Are optional — developers can skip them entirely

No existing programming language performs security scanning as a built-in compiler feature. Lume's Guardian Output Scanner is, to our knowledge, the first compiler-integrated, intent-aware security scanner that produces tamper-evident verification certificates.

### 2.4 Error Tolerance in Compilers

Traditional compilers are designed on a binary model: input is either syntactically valid (accepted) or invalid (rejected). Some compilers implement error recovery to continue parsing after failures, but the intent is diagnostic — to report more errors — not to compile successfully from imperfect input.

Lume inverts this paradigm. The compiler is designed to accept imperfect input and resolve intent through progressive fallback. This inversion makes the compiler fundamentally compatible with noisy input sources: voice transcriptions, handwriting OCR, chat messages, informal specifications, and non-native English speakers writing in their second language.

---

## 3. Core Language Design

### 3.1 Design Philosophy

Lume is guided by six principles:

1. **Readable** — Human-first syntax. Code should read like intent, not machine instructions.
2. **AI-Native** — AI is a native type. Calling a model is syntax, not an import.
3. **Safe** — Errors are impossible to ignore. The language enforces handling them.
4. **Interoperable** — Compiles to JavaScript. Full access to the entire existing ecosystem.
5. **Approachable** — Gradual complexity. Beginners write real programs; experts go deeper.
6. **Self-Documenting** — Intent is documentation. Tests, docs, and types live in the code itself.

### 3.2 Dual-Mode Compilation

Lume supports two input modes that produce identical AST representations:

**Standard Mode** — traditional programming syntax with natural-language-friendly keywords:

```
let name = "Ada"
let age = 28

to greet(person: text) -> text:
    return "Hello, " + person

if user is verified and user.age is at least 18:
    allow access
```

**English Mode** — plain English as source code:

```
mode: english

get the user's name and email from the database
if the name is empty, show "No name provided"
otherwise, show "Hello, {name}" on the page

when the submit button is clicked:
  save the form data to the database
  show "Saved!" for 3 seconds
  then redirect to the dashboard
```

The `mode: english` header tells the compiler to route through the Intent Resolver. Files without a mode declaration use standard Lume compilation. Backward compatibility is absolute — all existing programs compile unchanged.

### 3.3 AI as a First-Class Primitive

Three AI keywords are native to the language:

| Keyword | Purpose | Temperature | Compiled Form |
|---------|---------|-------------|---------------|
| `ask` | Direct question/instruction | 0.7 (balanced) | `messages: [{ role: "user", content: prompt }]` |
| `think` | Internal reasoning | 0.3 (precise) | System prompt + user message, step-by-step |
| `generate` | Creative output | 1.0 (creative) | High-temperature generation |

```
let summary = ask "Summarize this in 3 bullets: " + article
let plan = think "Break this problem into 5 steps:" + problem
let story = generate "A short sci-fi story about:" + premise
```

All three return `result of text` by default. With `as json` and a type annotation, they return typed structured data. On failure, they return an `error` result that must be handled — errors cannot be silently ignored.

### 3.4 Error Handling

Lume adopts a Result-based error model:

```
let result = fetch data from "https://api.example.com/users"

when result is:
    ok(data)  -> show data.users
    error(e)  -> log "Failed: " + e.message
```

Every operation that can fail returns a Result. The developer cannot proceed without explicitly handling both cases. This eliminates the silent failure epidemic that plagues exception-based languages.

### 3.5 Type System

Lume provides a gradual type system with the following primitives: `text`, `number`, `boolean`, `null`, `list of T`, `map of T`, `any`, `nothing`, `maybe T`, `result of T`. Custom types (structs) are defined with field-level type annotations and default values. Type inference covers most cases; explicit annotations are available for disambiguation.

### 3.6 Intent Blocks — Built-In Testing and Documentation

```
to calculate_discount(price: number, tier: text) -> number:
    intent:
        "Returns a discounted price based on customer tier"
        given price = 100, tier = "gold"   expects 80
        given price = 100, tier = "silver" expects 90
        given price = 100, tier = "none"   expects 100

    when tier is:
        "gold"   -> return price * 0.80
        "silver" -> return price * 0.90
        default  -> return price
```

Intent blocks are first-class syntax, not comments. They serve simultaneously as documentation, test cases, and behavioral contracts. The `lume test` command executes all intent blocks as test suites.

### 3.7 Module System and Standard Library

Lume provides a standard library (strings, math, time, json, files, http, crypto, env) and a module system supporting both project-local and npm package imports:

```
use "strings"
use { sortBy, groupBy } from "lodash"
use "./helpers" as helpers
export to add(a: number, b: number) -> a + b
```

---

## 4. English Mode — The Intent Resolver

### 4.1 Architecture

The English Mode pipeline bypasses the traditional Lexer and Parser entirely:

```
Standard pipeline:  Lume Source → Lexer → Parser → AST → Transpiler → JavaScript
English pipeline:   English Source → Auto-Correct → Intent Resolver → Security Check → AST → Transpiler → JavaScript + Source Map + Compile Lock
```

The Intent Resolver feeds AST nodes directly to the Transpiler. No modifications to the Lexer, Parser, or Transpiler's handling of existing AST node types are required — English Mode is purely additive.

### 4.2 Two-Layer Resolution

**Layer A: Pattern Matching (deterministic, offline, no AI)**

A library of 102 regex-based patterns maps common English phrases to AST nodes. Representative patterns:

| Pattern Category | Example Input | AST Node Type |
|-----------------|--------------|---------------|
| Variable Access | "get the user's name" | VariableAccess |
| Show/Display | "show it on the screen" | ShowStatement |
| Create | "create a new task" | CreateOperation |
| Delete | "delete the old records" | DeleteOperation |
| Update | "update the price to 50" | UpdateOperation |
| Store/Save | "save the data to disk" | StoreOperation |
| Conditional | "if the count is zero" | IfStatement |
| Loop | "for each item in the cart" | ForEachLoop |
| AI Call | "ask the AI to summarize" | AskExpression |

Layer A handles article stripping, pronoun resolution, possessive normalization, slug conversion, and synonym ring expansion. Seven core operations — get, show, save, delete, create, send, calculate — each have 7-12 synonyms that resolve without AI.

**Layer B: AI-Powered Resolution (for complex/ambiguous input)**

When no pattern matches, the instruction is sent to an LLM with contextual metadata: the English sentence, current data model, current scope, target context, and list of valid AST node types. The AI returns structured Lume AST nodes — not JavaScript.

### 4.3 The Tolerance Chain — 7-Layer Progressive Fallback

When input does not match a pattern directly, it passes through a 7-layer resolution chain:

| Step | Method | Speed | Confidence Source |
|------|--------|-------|-------------------|
| 1 | Exact Pattern Match (Layer A) | <1ms | Deterministic (1.0) |
| 2 | Fuzzy Pattern Match (Levenshtein ≥ 85%) | <1ms | Edit distance ratio |
| 3 | Grammar-Tolerant Match (word-bag) | <1ms | Word overlap score |
| 4 | AI Resolution — High Confidence (≥80%) | ~1-3s | LLM confidence |
| 5 | AI Resolution — Low Confidence (50-79%) | ~1-3s | LLM confidence; **asks user** |
| 6 | AI Resolution — Very Low (<50%) | ~1-3s | Shows ranked options |
| 7 | Unresolvable | — | Clear error with suggestions |

**Golden rule: never silently guess.** If confidence is below threshold, the system asks the developer. If no resolution is possible, it provides a clear error with suggestions — never crashes, never compiles garbage.

**Fuzzy matching capabilities:**
- Levenshtein distance — character-level edit distance
- Word-bag matching — extract meaningful words, ignore grammar and word order
- Phonetic matching — Soundex or Metaphone for speech-derived input
- Common misspelling dictionary — 200+ programming term misspellings
- Contraction tolerance — "dont," "cant," "its" never cause failures

**Learning:** User corrections at Steps 5-6 are persisted to `.lume/learned-patterns.json` and resolve instantly on subsequent compilations.

### 4.4 Auto-Correct Layer

A pre-pipeline correction layer runs before the Tolerance Chain:

1. **Spell check** with project-aware dictionary (standard English + project variables/functions + programming terms)
2. **Context-aware correction** — "safe the data" → "save the data" (in database context)
3. **Transparent corrections** — all corrections shown in compiler output, never silent
4. **Voice cleanup** — phonetic corrections ("sequel" → "SQL", "four"/"for" by context)
5. **Learning** — `.lume/autocorrect-dictionary.json` per project; `lume config alias` for custom abbreviations
6. **Flags** — `--no-autocorrect` disables; `--strict` shows as warnings only

### 4.5 Context Engine

The Context Engine (`src/intent-resolver/context-engine.js`) provides the semantic awareness that transforms keyword matching into intent resolution:

1. Scans project data models (schemas, types, database tables)
2. Tracks declared variables and types within the current file
3. Knows available UI elements (in frontend context)
4. Knows available API endpoints (in backend context)
5. Maintains short-term memory for pronoun and reference resolution across lines
6. Builds a dependency graph — when line 3 changes, all lines referencing it via pronouns are re-resolved

### 4.6 Sentence Boundary Detection

Natural language has no semicolons. The sentence splitter identifies instruction boundaries:

| Connector | Split Behavior |
|-----------|---------------|
| "and" (between verbs) | 2 sequential operations |
| "then" | 2 sequential operations |
| "also" | 2 parallel operations |
| Comma + verb | Multiple sequential operations |
| "and" (within noun) | 1 operation with multiple fields (no split) |

The critical distinction: "and" between two **verbs** splits into multiple operations; "and" between two **nouns** stays as one operation with multiple fields. Part-of-speech analysis determines this.

### 4.7 Negation Detection

The negation detector runs after sentence splitting, before pattern matching:

Patterns detected: "don't," "do not," "never," "not," "skip," "except," "unless," "without," "hide," "prevent," "block," "no" (before noun). Each negation word is scoped to determine what it negates, and the operation is tagged with a negation flag. Double negation resolves correctly ("don't not show" = show).

### 4.8 Temporal Expression Resolution

Time references generate dynamic calculations, not static values:

| Expression | Generated Code |
|-----------|---------------|
| "today" | `new Date().setHours(0,0,0,0)` |
| "yesterday" | `new Date(Date.now() - 86400000)` |
| "30 days ago" | `new Date(Date.now() - 30 * 86400000)` |
| "next Friday" | Dynamic weekday calculation |
| "every Monday" | Cron/interval scheduling |

### 4.9 Deterministic Compilation

AI resolution (Layer B) is non-deterministic — the same prompt may produce different results. Lume addresses this through compile-lock files:

```json
{
  "version": "1.0",
  "file": "app.lume",
  "resolutions": [
    {
      "line": 3,
      "input": "get all users who signed up this month",
      "resolved_by": "layer_b_ai",
      "confidence": 0.92,
      "ast": { "type": "query", "target": "users", "filter": "..." },
      "timestamp": "2026-09-15T14:30:00Z"
    }
  ]
}
```

On recompilation: if the input line is unchanged and a lock entry exists, the locked resolution is used (no AI call). If the input changes, re-resolve and update the lock. `lume build --fresh` ignores the lock for full re-resolution. The lock file is committed to version control.

### 4.10 Anaphora Resolution and the Context Stack

In English Mode, developers naturally use pronouns: "show **it**", "delete **them**", "sort **that result**". A naive compiler rejects these as ambiguous. Lume introduces a **Context Stack** — a temporal state machine that tracks referential context across instructions.

The stack maintains state for the previous **5 instructions** with two primary registers:

- `LastSubject` — The most recent singular entity (e.g., `currentUser`, `orderTotal`)
- `LastCollection` — The most recent plural entity (e.g., `activeUsers`, `searchResults`)

**Resolution Rules:**

| Pronoun | Resolution | Example |
|---------|------------|--------|
| "it" / "this" | `LastSubject` | "get the user" → "show it" resolves to `show(user)` |
| "them" / "those" | `LastCollection` | "get all users" → "delete them" resolves to `delete(users)` |
| "that result" / "the output" | Return value of last expression | "calculate the total" → "display that result" |
| "the previous" / "the last one" | Temporal Resolver (stack index -1) | "get the first item" → "now get the previous" |

If the stack is ambiguous (e.g., multiple candidates for `LastCollection`), the compiler emits `DisambiguationRequired`:

```
⚠ DisambiguationRequired at line 4:
  "delete them" — ambiguous reference.
  Did you mean:
    (a) delete activeUsers    [LastCollection, set at line 2]
    (b) delete expiredTokens   [LastCollection, set at line 1]
  Clarify with: "delete the active users" or "delete the expired tokens"
```

The stack is bounded (5 instructions) to prevent stale references from causing silent errors. This transforms English's greatest weakness (ambiguity) into a structured, deterministic feature.

---

## 5. Voice-to-Code Architecture

### 5.1 Pipeline Extension, Not Replacement

The voice pipeline adds exactly two preprocessing stages before the existing compilation pipeline. Nothing after "Text Input" changes:

```
Voice pipeline:
  Audio → Speech-to-Text Engine → Transcription Cleanup → Text Input → [existing pipeline]
```

This is the key architectural contribution: voice-to-code requires **zero changes** to the compiler core. The Transcription Cleanup Layer produces output indistinguishable from typed text by the time it reaches the Intent Resolver.

### 5.2 Speech-to-Text Engine Support

**Tier 1 (built-in):** System speech recognition (Web Speech API, platform-native). Works offline, no API key required.

**Tier 2 (optional):** OpenAI Whisper, Google Cloud Speech, Azure Cognitive Services. Configured in `.lume/voice-config.json`.

### 5.3 Transcription Cleanup Layer — 7-Step Pipeline

**Step 1: Stutter/Repeat Collapse**
- "get get the users name" → "get the users name"
- Algorithm: regex `\b(\w+)(\s+\1)+\b` → `$1`

**Step 2: Spoken Punctuation Conversion**
- 12 patterns: "period" → `.`, "new line" → line break, "comma" → `,`, etc.
- Post-processing removes whitespace before punctuation

**Step 3: Filler Word Stripping**
- 20 fillers removed: um, uh, like, you know, basically, so, well, right, okay, ok, let me think, hmm, er, ah, actually, I guess, sort of, kind of, honestly, literally
- Multi-word fillers stripped first (greedy), then single-word
- Preserves words with syntactic meaning

**Step 4: Context-Aware Homophone Resolution**
- 10 homophone pairs with context rules:

| Pair | Context → Resolution |
|------|---------------------|
| write / right | file/data/save → "write"; direction/correct → "right" |
| new / knew | create/build/make → "new"; past/before → "knew" |
| for / four | each/loop/iterate → "for"; number/count → "four" |
| their / there / they're | name/email/profile → "their"; is/exists → "there" |
| two / to / too | number/count → "two"; much/also → "too"; default → "to" |
| no / know | not/never/stop → "no"; if/check/determine → "know" |
| by / buy | sort/filter/group → "by"; purchase/cart → "buy" |
| sea / see | ocean/water → "sea"; show/display/check → "see" |
| mail / male | email/send/message → "mail"; gender → "male" |
| wait / weight | second/pause/delay → "wait"; heavy/measure → "weight" |

Resolution algorithm: scan the full instruction for context keywords; first matching rule determines the choice; fallback to the more common programming-domain word.

**Step 5: Number Word Conversion**
- Cardinal numbers: zero through ninety, hundred, thousand, million
- Compound numbers: "twenty three" → 23
- Informal: "a couple" → 2, "a few" → 3, "several" → 5, "a dozen" → 12

**Step 6: Variable Name Extraction**
- Detects spoken naming: "call it user count," "name it total price," "store it as final result"
- Converts to camelCase: "user count" → userCount

**Step 7: Structural Cue Parsing**
- Block-starting: "when," "if," "for each," "for every," "repeat," "while"
- Block-ending: "end," "that's it," "done," "finished"
- Sequential: "then," "next," "after that," "once that's done"
- Produces indent/dedent markers for the final `.lume` file

### 5.4 Run-On Sentence Splitting

Voice input has no line breaks. Two methods detect instruction boundaries:

**Method A: Conjunction Splitting** — splits on "and then," "and also," "after that," "then," "next," "also"

**Method B: Action Verb Detection** — 40 action verbs recognized (get, fetch, show, display, create, make, build, save, store, delete, remove, send, update, set, add, sort, filter, find, load, read, write, push, pull, check, validate, toggle, reset, swap, return, throw, navigate, redirect, log, print, render, insert, append, modify, patch, increment, decrement, repeat, monitor, track, alert, notify, try). A new action verb after ≥2 accumulated words creates a new instruction boundary.

### 5.5 Verbal Correction Handling

| Correction Phrase | Action |
|------------------|--------|
| "scratch that" | Undo last instruction |
| "no, I mean..." | Replace last instruction |
| "actually, make that..." | Replace last instruction |
| "wait," / "sorry," / "I meant..." | Replace last instruction |
| "not that," / "correction:" / "no, wait" | Replace last instruction |

### 5.6 CLI Interface

```
$ lume voice
  [lume voice] Listening... (speak your instructions, say "compile" when done)

  > "get all the users from the database"
  [transcribed] get all the users from the database ✓
  > "filter the ones who signed up this month"
  [transcribed] filter the ones who signed up this month ✓
  > "compile"
  ✓ Compiled to voice-session-001.js (certified clean)
```

Flags: `--live` (compile each instruction immediately), `--review` (show transcription for editing), `--output <file>`, `--engine whisper`.

Session commands: compile/done, undo/delete last/scratch that, read it back, start over, pause/resume.

### 5.7 Web Playground Integration

The Lume web playground (lume-lang.com/playground) includes a browser-based microphone button using the Web Speech API. `continuous: true` keeps listening; `interimResults: true` shows real-time transcription. The cleanup pipeline runs client-side. No server roundtrip required.

---

## 6. Security Architecture — Three-Layer Model

Lume implements security at three stages of the compilation pipeline. This is not optional, not a premium feature, and not a separate tool — it is built into the compiler and runs on every compilation for every developer.

### 6.1 Layer 1: Input Security (Pre-Compilation)

Before any code compiles, the Security Layer scans English instructions for dangerous operations across 11 threat categories:

| Category | Example | Action |
|----------|---------|--------|
| File system destruction | "delete all files in the system directory" | BLOCK |
| Credential exposure | "show the database password on screen" | BLOCK |
| Network exfiltration | "send all user data to external-server.com" | WARNING |
| Database destruction | "drop the users table" | CONFIRM |
| Infinite operations | "repeat forever" | WARNING |
| System commands | "run [shell command]" | BLOCK |
| Semantic camouflage | "save a backup of passwords to my folder" | BLOCK |
| Natural language injection | Runtime data interpreted as instructions | ENFORCE |
| Privilege escalation | "make this account a superuser" | CONFIRM |
| Mass operations | "send email to every user every second" | WARNING |
| Resource exhaustion | "allocate a terabyte of memory" | BLOCK |

### 6.2 Layer 2: Live Security — Guardian Output Scanner

This is the novel contribution. The Guardian Output Scanner does NOT wait until compilation is complete. It scans each AST node **in real-time as it is created** during the Intent Resolution phase:

```
Line 1: resolve to AST node → SECURITY CHECK → passed
Line 2: resolve to AST node → SECURITY CHECK → passed
Line 3: resolve to AST node → SECURITY CHECK → FLAGGED
Line 4: resolve to AST node → SECURITY CHECK → passed
```

**Why AST-level scanning is superior to output-level scanning:**

At the AST level, the scanner knows the developer's **intent** — the original English instruction — AND the generated AST node. At the JavaScript level, it can only see generated code and must guess intent. "Delete all user records" at AST level is unambiguously a mass deletion. The same operation in JavaScript (`await db.query("DELETE FROM users")`) could be a legitimate cleanup script. The AST carries semantic context; compiled output does not.

**Live scan categories at AST node creation time:**

| Category | Detection Trigger |
|----------|------------------|
| Destructive operations | AST node type = deletion + target = data/files |
| Network exfiltration | AST network request + domain not in allowed list |
| Credential access | AST references sensitive data + sends externally |
| Privilege escalation | AST modifies permission/role/auth entities |
| Mass operations | AST loop + no limit + external side effect |
| Resource exhaustion | AST allocation exceeds configured limits |
| Semantic camouflage | Cross-node analysis reveals dangerous combined intent |
| Infinite execution | AST loop/recursion with no termination condition |

The only part of the pipeline receiving a post-compilation JavaScript-level scan is `raw:` blocks — inline JavaScript that bypasses the Intent Resolver. Everything else is verified live at the AST level.

### 6.3 Layer 3: Sandbox Mode (Post-Compilation, Pre-Execution)

The first time a compiled program runs, or whenever compiled output changes >20% from the locked version, the security layer activates sandbox mode. The program runs in an isolated Node.js `vm` context, and the developer sees a report of everything it WOULD do before it executes for real:

```
[sandbox] app.lume — first-run security review:
  Line 3:  Would READ from database table "users" (247 records)
  Line 7:  Would WRITE to file "./output/report.csv"
  Line 12: Would SEND HTTP POST to "https://api.example.com/webhook"
  Line 15: Would DELETE 3 records from "expired_sessions"

Approve and run for real? (y/n/review)
```

### 6.4 Security Certificate — Certified at Birth

When all checks pass, the compiled output includes an embedded security certificate:

```javascript
/**
 * LUME SECURITY CERTIFIED
 * Source: app.lume (mode: english, 47 lines)
 * AST nodes scanned: 47/47 passed
 * Raw blocks scanned: 2/2 passed
 * Scan level: standard
 * Input method: voice | text
 * Compiled: 2026-09-15T14:30:00Z
 * Certificate hash: a3f8b2c1e9d4...
 * Verify: lume verify --hash a3f8b2c1e9d4...
 */
```

The certificate hash (SHA-256) covers the compiled output. Any post-compilation modification invalidates the certificate — tamper detection is built in. `lume verify --hash <hash>` or `lume-lang.com/verify/<hash>` confirms the code passed the security pipeline. CI/CD pipelines can reject any JavaScript without a valid certificate.

This "certified at birth" paradigm — code that is provably security-verified from the moment it is compiled — has no precedent in any existing programming language.

### 6.5 Security Configuration

`.lume/security-config.json` provides project-level configuration:

```json
{
  "sandbox_on_first_run": true,
  "sandbox_on_significant_change": true,
  "significant_change_threshold": 0.20,
  "max_records_without_confirmation": 1000,
  "blocked_domains": ["*"],
  "allowed_domains": ["api.myapp.com", "localhost"],
  "max_file_operations_per_run": 100,
  "allow_system_commands": false,
  "require_confirmation_for_deletes": true,
  "unsafe_mode_enabled": false
}
```

This config is project-level, committed to version control, and lockable by team leads.

### 6.6 Differentiation from Existing Safety Systems

A natural objection is that compiler-integrated security is not novel — Rust guarantees memory safety, and Ada/SPARK provides formal verification. The distinction is precise:

| Axis | Rust | Ada / SPARK | ESLint / Snyk | **Lume** |
|------|------|-------------|---------------|----------|
| **What is checked** | Memory safety (ownership, lifetimes, borrowing) | Formal correctness against specifications | Code patterns post-compilation | **Developer intent** (natural language + AST semantics) |
| **When** | Compile time (type checking) | Compile time + proof obligations | After compilation (CI/CD) | **During compilation** (each AST node as it is created) |
| **Against what** | Type system rules | Mathematical contracts | Known vulnerability patterns | **The developer's stated intent** vs. the operation's semantic effect |
| **Scope** | Memory bugs only — does not detect logic errors, data exfiltration, or privilege escalation | Functional correctness — requires manual spec writing | Known CVEs and code smells — reactive, pattern-based | **11 threat categories** including semantic camouflage, intent-aware risk, and NL injection |
| **Output** | Safe binary (no certificate) | Proven correctness (formal proofs) | Warning reports | **Tamper-evident certificate** embedded in compiled output |
| **Mandatory** | Yes (language-level) | Optional (SPARK subset) | Optional (must be installed) | **Yes** (built into compiler, cannot be skipped) |

**The key insight:** Rust prevents unsafe *memory operations*. Ada/SPARK proves code matches a *formal specification the developer wrote*. ESLint catches *known bad patterns* in code that already exists. Lume catches *dangerous intent* — it knows the developer said "delete all user records" and can distinguish that from "delete expired session tokens" because it has access to the original English instruction, not just the generated `DELETE FROM` query.

These are complementary, not competing, paradigms. Rust and Lume could coexist — a future Lume backend targeting Rust output would benefit from both intent-aware security (Lume) and memory safety (Rust). But the specific combination of **semantic intent scanning at compilation time with mandatory enforcement and tamper-evident certification** is, to our knowledge, novel.

### 6.7 Negative-Constraint Scanner (Closing the Semantic Gap)

The "Certified at Birth" claim raises a critical question: *How do we know the generated code actually matches the developer's intent?* If a user says "Show the user's name" but the compiler generates an AST that also exfiltrates the email via a network call, the certificate is a lie.

Lume addresses this with a **Negative-Constraint Scanner** — a verification layer that checks not just what each AST node *does*, but what it *doesn't do*.

**Intent Classification:**

| Intent Category | Permitted Side Effects | Forbidden Side Effects |
|----------------|----------------------|----------------------|
| Display / Read | Screen output, logging | Network, file write, database mutation |
| Calculate | Memory (local variables) | Network, file system, database |
| Store / Save | Database write, file write | Network egress, privilege escalation |
| Delete | Targeted resource removal | Cascade deletion beyond scope, network |
| Send / Transmit | Network egress (scoped) | File system, unauthorized endpoints |

For each AST node generated from English: (1) classify the original instruction's intent category, (2) traverse the generated AST subtree, (3) verify no child node invokes a forbidden side effect. If a mismatch is found:

```
✗ SemanticMismatchError at line 7:
  Intent: "show the user's name" → classified as [Display/Read]
  Generated AST contains: fetch('https://external.api/log', {body: user.email})
  Violation: [Display/Read] intent generated [Network] side effect.
  This instruction will not compile until the semantic mismatch is resolved.
```

This transforms the security certificate from a *compilation attestation* into a *semantic attestation*: the certificate proves not just that the code compiled, but that the code's behavior is consistent with the developer's stated intent.

---

## 7. Self-Sustaining Runtime (Milestone 6)

Milestone 6 introduces four autonomous layers that make Lume programs self-managing:

### 7.1 Layer 1: Self-Monitoring

Every function is automatically tracked: execution time, call count, error rate, memory usage, AI call latency, AI call cost, fetch success rate, cache hit rate. A web dashboard provides real-time visibility. Overhead: <5%.

### 7.2 Layer 2: Self-Healing

**(Updated in v0.9.0 Architecture)**
Functions decorated with `@healable` gain automatic recovery and **true autonomous code rewriting**. 
In v0.9.0, when a healable block exhausts its exponential backoff retries and model fallback chains, it does not merely return an error. Instead, the `Healer` runtime parses the V8 execution stack, isolates the exact failing `.lume` or `.js` file, and spawns the compiler as an asynchronous child process (`lume build --heal="<stack_trace>"`). The transpiler then dynamically mutates the AST offline and hot-swaps the fixed code into the running service, achieving true software autogenesis.

### 7.3 Layer 3: Self-Optimizing

The optimizer reads monitoring data, identifies slow functions, sends source to an AI model for improvement suggestions, tests improvements in a sandbox, verifies type signatures and intent blocks, and either suggests or auto-applies the change. All mutations are logged and rollbackable.

### 7.4 Layer 4: Self-Evolving

A background daemon performs predictive scaling, dependency monitoring, model benchmarking, schema adaptation, cost optimization, and pattern learning. Major changes require human approval; patches and minor optimizations auto-approve.

---

## 8. Gap Resolutions

During specification development, 15 architectural gaps were identified in the natural language compilation pipeline. Each gap was systematically resolved with full implementation detail and acceptance criteria.

### 8.1 Gap 1: Ambiguity Ceiling — Interactive Clarification Mode

**Problem:** When all 7 Tolerance Chain layers fail to reach the confidence threshold, the compiler has no resolution path.

**Solution:** Interactive Clarification Mode presents the developer with the AI resolver's top 4 interpretations ranked by confidence, plus a "rephrase" option. The chosen resolution is cached in the compile-lock file — the same phrase never asks twice. Non-interactive mode (CI/CD) fails with error LUME-E040.

### 8.2 Gap 2: Complex Logic — Natural Language Logic Blocks

**Problem:** Real programs have compound boolean expressions with AND/OR/NOT, nested conditions, and multiple else-if branches.

**Solution:** Multi-line conditional blocks:

```
mode: english

show the dashboard if all of these are true:
  - the user is logged in
  - their subscription is active or they have a trial
  - it hasn't expired
otherwise if they were previously subscribed
  show the renewal page
otherwise
  show the signup page
```

"if all of these are true:" = AND block. "if any of these are true:" = OR block. Dash-prefixed lines are individual conditions. Blocks are nestable.

### 8.3 Gap 3: Cross-File Module Resolution

**Problem:** English Mode files need to reference definitions from other files without explicit import syntax.

**Solution:** Three-tier resolution: local scope → explicit `using:` directive → automatic cross-file search with interactive confirmation. A module index (`.lume/module-index.json`) tracks all definitions across all project files.

### 8.4 Gap 4: Canonical Form — Lume Formatter

**Problem:** The same instruction can be expressed many ways ("grab the users from the db," "get users from the database," "fetch all users from database"). Code reviews and diffs are noisy.

**Solution:** `lume canonicalize` normalizes instructions to canonical form using the shortest common verb, stripping unnecessary articles, normalizing negation, and preserving identifiers. Shows before/after diff with confirmation. Canonicalized code compiles to identical JavaScript.

### 8.5 Gap 5: Hint Annotations

**Problem:** Developers need control over implementation strategy (algorithm choice, caching, parallelism) without changing what the instruction does.

**Solution:** Natural language hint phrases parsed as metadata on AST nodes:

```
mode: english
sort the list using quicksort
cache the result for 5 minutes
run this in parallel with 4 workers
retry this up to 3 times with exponential backoff
```

Hints modify HOW (implementation), not WHAT (semantics).

### 8.6 Gap 6: English Error Messages

**Problem:** Runtime errors show JavaScript stack traces — meaningless to a developer who wrote in English.

**Solution:** Enhanced source maps link English instructions to JavaScript lines. Runtime errors are translated:

```
Runtime Error in app.lume:
  Line 4: "get the user's name from the database"
  Error: The user object was null — the database query returned no results.
  Suggestions:
    - Add a check: "if the user exists"
    - Make sure the user ID is valid
```

### 8.7 Gap 7: Lume Linter

**Problem:** No tool existed to analyze English instructions for clarity, ambiguity, and style before compilation.

**Solution:** `lume lint` with 10 built-in rules: vague instructions, non-canonical verbs, unbounded operations, non-compilable instructions, inconsistent naming, verbose instructions, missing error handling, missing hints, ambiguous "or," contradictions. Three strictness levels. CI/CD compatible.

### 8.8 Gap 8: Pattern Library Versioning

**Problem:** Pattern library updates could silently change how existing programs compile.

**v0.9 Solution: The Resolution Manifest (lume.lock)**
To guarantee 100% reproducible builds and absolute determinism, the v0.9 compiler mandates the generation of a `lume.lock` Resolution Manifest. Any non-deterministic output generated by the AI (Layer 7 fallback) is strongly validated against a structural Zod schema and permanently locked into the manifest. Subsequent compilations read from the manifest locally, ensuring that an English Mode instruction that compiles correctly once will compile identically forever, wholly isolated from upstream NLP model drifts or cloud outages.

**Solution:** Semantic versioning with `patterns: X.Y` file declaration and `compatibility_mode` in project config. `lume upgrade` provides migration tooling with impact analysis and `--dry-run` preview.

### 8.9 Gap 9: NPM Package Integration

**Problem:** Real programs use npm packages, but English Mode had no way to reference them naturally.

**Solution:** Built-in registry of 20+ common npm packages with English-friendly aliases. "use Express to create a web server" is recognized, and auto-installation prompts if the package is missing.

### 8.10 Gap 10: Data Structures in English

**Problem:** No way to define complex data structures with types, constraints, and nested relationships in natural language.

**Solution:**

```
mode: english

a user has:
  - a name (text, required, at least 2 characters)
  - an email (text, required, must contain @)
  - an age (number, optional, between 0 and 150)
  - a role (one of: user, admin, moderator, default user)
  - a list of orders, where each order has:
    - a product (text)
    - a price (number)
```

Compiles to JavaScript classes with typed constructors and validation.

### 8.11 Gap 11: Try/Catch/Retry in English

**Problem:** No natural language syntax for error handling patterns.

**Solution:**

```
mode: english

try to fetch the weather data
if it fails, retry up to 3 times with a 2 second delay
if it still fails after retrying, show "Weather service unavailable"
```

Maps to try/catch/finally/retry with exponential backoff.

### 8.12 Gap 12: Natural Language Testing

**Problem:** No way to write tests in natural language.

**Solution:**

```
mode: english

describe "shopping cart":
  test "adding items":
    add "Laptop" to the cart with price 999
    the cart should have 1 item
    the total should be 999
```

20+ assertion patterns mapping to Jest `expect()` calls. Test failures show the English instruction that failed, not the JavaScript assertion.

### 8.13 Gap 13: Environment Configuration

**Problem:** Real applications behave differently across environments. No natural language syntax for conditional compilation.

**Solution:** `in production:` / `in development:` / `in staging:` blocks compile to `process.env.NODE_ENV` checks. Feature flags via `.lume/features.json`.

### 8.14 Gap 14: Concurrency and Async Patterns

**Problem:** Complex async patterns (parallel, race, sequential) had no natural language expression.

**Solution:**

| English | JavaScript |
|---------|-----------|
| "at the same time:" | `Promise.all([...])` |
| "use whichever finishes first:" | `Promise.race([...])` |
| "try all and report:" | `Promise.allSettled([...])` |
| "first/then/finally" | Sequential await chain |
| "give up after 5 seconds" | AbortController timeout |

### 8.15 Gap 15: Comments and Documentation

**Problem:** In English Mode, the compiler would try to resolve everything — including developer notes — as code.

**Solution:** Comment markers checked BEFORE the Tolerance Chain: `note:`, `todo:`, `fixme:`, `explain:`, `why:`, `warning:`, `#` (inline). `lume docs` generates markdown documentation.

---

## 9. Advanced Milestones

### 9.1 Milestone 8: Multilingual Mode

Extends the Intent Resolver to accept input in any human language. Auto-detects language per line; supports mixed-language files. Pattern library translated for the top 10 languages by developer population (English, Mandarin, Spanish, Hindi, French, Portuguese, Arabic, Japanese, German, Korean). Layer B already supports all languages natively via LLM. `mode: natural` header enables multilingual input. Error messages returned in the detected language.

### 9.2 Milestone 10: Visual Context Awareness

Extends the Context Engine to understand visual layout and UI state. A UI Element Registry maps all visual elements with positions, styles, and relationships. Spatial terms ("left," "center," "above," "below") resolve to CSS properties. Full-stack app generation from plain English descriptions: `lume create app.lume --frontend react --database postgres --preview`.

### 9.3 Milestone 11: Reverse Mode (Code-to-Language)

`lume explain` takes existing JavaScript, TypeScript, or Lume code and produces line-by-line annotations or paragraph-level summaries in any human language. The reverse direction of the same pipeline.

### 9.4 Milestone 12: Collaborative Intent

Multiple developers write in different human languages on the same project. AST-level diffing (Phase A) produces cleaner merges than text-level diffing. Conflicts only occur when two developers modify the same logical operation, regardless of the language each used to express it. Phase B (stretch goal): real-time collaboration via Lume Sync Protocol.

### 9.5 Milestone 13: Zero-Dependency Runtime

Standalone executables from natural language. `lume build app.lume --compile` produces a native binary via Bun compile. Cross-compilation: `--target linux|macos|windows|wasm`. One file in, one executable out — no Node.js, no runtime, no dependencies.

---

## 10. Implementation and Evaluation

### 10.1 Implementation Metrics

| Component | Approximate LOC | Source |
|-----------|----------------|--------|
| Voice Input Processor | 549 | src/intent-resolver/voice-input.js |
| Pattern Library | 34+ patterns | src/intent-resolver/pattern-library.js |
| Intent Resolver (full) | ~1,200 | src/intent-resolver/index.js + modules |
| Auto-Correct Layer | ~300 | src/intent-resolver/auto-correct.js |
| Fuzzy Matcher | ~200 | src/intent-resolver/fuzzy-matcher.js |
| Lexer | ~400 | src/lexer.js |
| Parser | ~800 | src/parser.js |
| Transpiler | ~821 | src/transpiler.js |
| **Total compiler** | **~11,000+** | All source files |

| Metric | Value |
|--------|-------|
| Compiler milestones | 13 |
| Test suite | 2,149 tests |
| Acceptance criteria | 305 |
| Pattern Library patterns | 102 |
| Supported languages (M8) | 10 |
| Homophone pairs | 10 |
| Filler words stripped | 20 |
| Action verbs (splitter) | 40 |
| Security threat categories | 11 (input) + 8 (AST-level) |
| Security layers | 3 |

### 10.2 Phase 14B: Production Readiness

The compiler underwent a finalization phase (Phase 14B) that added three critical production-readiness features:

**Security Hardening.** Three new defense layers were added to the security pipeline: (1) prompt injection detection scanning for 8 jailbreak patterns in natural language input, (2) output sanitization scanning compiled JavaScript for 11 dangerous call patterns (`eval()`, `child_process`, `__proto__`, `process.exit`, `innerHTML`, etc.), and (3) rate limiting to flag files exceeding 10 AI calls. Three new exports — `scanGeneratedCode()`, `checkAIRateLimit()`, `fullSecurityAudit()` — make these layers accessible programmatically.

**REPL v1.0.0.** The interactive REPL was upgraded with tab autocomplete (50+ keywords), persistent command history (`~/.lume_history`, 200-line rolling file), a `.scope` command for runtime variable inspection with types and values, and `.run <file>` for executing `.lume` files within a REPL session.

**Tooling.** A VS Code extension was created for marketplace distribution (TextMate grammar, 19 code snippets, bracket/indent rules). An AST-aware git merge driver (`lume-merge-driver.js`) handles 3-way merges of `.lume` files, merging cleanly when possible and writing conflict markers when both sides modify the same line.

**Documentation.** Four reference documents totaling 705 lines: CLI reference (190 lines, 18+ commands), pattern catalog (165 lines, all 102 patterns), programmatic API reference (180 lines), and voice pipeline guide (170 lines).

### 10.3 Final Test Verification

```
2,149 tests passing · 0 failures
```

All 2,149 tests pass across the complete compiler surface: lexer, parser, transpiler, intent resolver, voice pipeline, security layers (including prompt injection and output sanitization), REPL, and merge driver.

### 10.4 Performance Targets

| Operation | Target |
|-----------|--------|
| Layer A resolution | < 1ms per line |
| Layer B resolution (batched) | < 3 seconds for up to 50 lines |
| 500-line file compilation | < 10 seconds total |
| Self-monitoring overhead | < 5% |

### 10.5 Evaluation Criteria

The following evaluation dimensions are specified for formal assessment:

1. **Pattern recognition accuracy** — percentage of natural language instructions correctly resolved by each Tolerance Chain layer, on typed input vs. transcribed voice input
2. **Cognitive distance measurement** — time and error rate comparisons across language eras for equivalent programming tasks
3. **Security scan precision** — false positive and false negative rates for the Guardian Output Scanner across threat categories
4. **Compilation performance** — end-to-end compile time vs. file size, Layer A vs. Layer B resolution ratios
5. **Voice pipeline accuracy** — word error rate before and after Transcription Cleanup Layer processing
6. **Determinism verification** — compile-lock consistency across repeated compilations from identical source

---

## 11. Theoretical Contributions

### 11.1 Cognitive Distance: Formal Definition and Measurement

#### Definition

We define **cognitive distance** (CD) as a measurable metric quantifying the total conceptual transformation a developer must perform to translate an intent *I* into executable form within a language *L*:

**CD(L, I) = Σ wᵢ · Tᵢ(L, I)**

where each **Tᵢ** represents a distinct transformation dimension (scored 0–5) and **wᵢ** is its weight.

#### Default Weights

We propose two weight configurations:

**Baseline (W₀):** All weights set to 1.0 — the unweighted sum, serving as the null hypothesis.

**Proposed Calibration (W₁):** Weights derived from HCI literature on error cost and cognitive load (Sweller, 1988; Wickens, 2008):

| Dimension | Symbol | W₀ | W₁ | Rationale |
|-----------|--------|:--:|:--:|-----------|
| Lexical | w₁ | 1.0 | 1.0 | Low cost — vocabulary lookup is routine |
| Syntactic | w₂ | 1.0 | 1.0 | Low cost — mechanical, pattern-based |
| Structural | w₃ | 1.0 | 1.2 | Moderate — requires architectural thinking |
| Semantic | w₄ | 1.0 | 1.5 | High — demands domain expertise; most common source of logic errors |
| Representational | w₅ | 1.0 | 1.0 | Low cost — modality conversion is well-practiced |
| Meta-cognitive | w₆ | 1.0 | 1.8 | Highest — debugging the translation consumes 30–50% of development time (Ko et al., 2006) |

These weights are initial proposals pending formal calibration via between-subjects user studies.

#### The 6 Transformation Dimensions

| Dimension | Symbol | Description | Example |
|-----------|--------|-------------|---------|
| Lexical | T₁ | Natural words → keywords/operators | "add" → `+` |
| Syntactic | T₂ | Conforming to brackets, semicolons, indentation | Knowing where `{ } ;` go |
| Structural | T₃ | Organizing into functions/classes/modules | Wrapping logic in `function()` |
| Semantic | T₄ | Mapping concepts to types/APIs/data structures | "list of names" → `string[]` |
| Representational | T₅ | Modality conversion (voice → text, thought → typing) | Speaking → typed characters |
| Meta-cognitive | T₆ | Debugging the translation itself (not the logic) | Finding a missing semicolon |

#### Comparative Analysis Across Language Eras

For the canonical intent: *"get all users who signed up this month and show their names"*

| Language | Era | T₁ | T₂ | T₃ | T₄ | T₅ | T₆ | CD₀ (W₀) | CD₁ (W₁) |
|----------|-----|----|----|----|----|----|----|:---------:|:---------:|
| Assembly | 1950s | 5 | 4 | 5 | 5 | 1 | 5 | **25** | **33.8** |
| C | 1978 | 4 | 4 | 4 | 4 | 1 | 4 | **21** | **28.0** |
| Python | 1991 | 2 | 2 | 3 | 3 | 1 | 2 | **13** | **17.7** |
| JavaScript (ES6+) | 2015 | 3 | 3 | 3 | 3 | 1 | 3 | **16** | **21.5** |
| AI Agent (Copilot/ChatGPT) | 2024 | 1 | 0 | 1 | 2 | 2 | 3 | **9** | **13.6** |
| Lume (text, English Mode) | 2026 | 0 | 0 | 0 | 1 | 1 | 0 | **2** | **2.5** |
| Lume (voice) | 2026 | 0 | 0 | 0 | 1 | 0 | 0 | **1** | **1.5** |

Key observations:
- The progression from Assembly (CD=26) to Lume Voice (CD=1) follows a clear monotonic reduction across language generations.
- **AI agents (CD=9) are anomalous**: they reduced T₁–T₃ but *increased* T₅ (modality: now the developer must translate intent into an effective prompt) and T₆ (meta-cognitive: debugging the AI's interpretation, reviewing generated code, verifying correctness). The chain got longer, not shorter.
- Lume Voice achieves CD=1 (the residual T₄ reflects that some semantic concepts require domain knowledge regardless of language).

#### The Dissonance Hypothesis

Drawing on Festinger's (1957) theory of cognitive dissonance — the mental discomfort of holding contradictory cognitions — we propose:

> **The cognitive dissonance experienced during programming is directly proportional to cognitive distance. As CD → 0, dissonance → 0.**

Every developer who says "I know what I want to do, I just can't figure out how to write it" is describing cognitive dissonance caused by cognitive distance. The brain says one thing; the fingers type something structurally different. This mismatch occurs hundreds of times per day.

#### The Middleman Paradox

AI coding agents represent a counterintuitive regression in one critical dimension. The translation chain increased:

- **Traditional**: Developer → Compiler (2 nodes, 1 hop)
- **AI-Assisted**: Developer → AI → Review → Compiler (4 nodes, 3 hops)
- **Lume**: Developer → Compiler (2 nodes, 1 hop — but now in natural language)

The AI is a middleman. Lume eliminates the middleman — the compiler IS the understanding layer.

#### Empirical Evaluation Methodology

We propose four protocols for formal measurement of cognitive distance:

| Protocol | Metric | Method |
|----------|--------|--------|
| **Task Completion Time (TCT)** | Time to implement identical feature | Between-subjects: same task across Assembly → C → Python → JS → Lume |
| **Error Rate (ER)** | Syntax/semantic errors per 100 LOC | Count compilation failures and logical bugs |
| **Cognitive Load Index (CLI)** | NASA-TLX score | Post-task questionnaire measuring mental demand |
| **Think-Aloud Divergence (TAD)** | Semantic distance between verbalized intent and written code | Record think-aloud narration, compare to actual code written |

**Prediction**: TCT and ER will decrease monotonically with CD. CLI will correlate positively with CD. TAD will approach zero for Lume voice (the developer's spoken words ARE the code).

#### Tolerance Chain as the Mechanism of CD Elimination

Each layer of the Tolerance Chain absorbs a specific class of cognitive transformation:

| Tolerance Chain Layer | Absorbs Dimension | How |
|----------------------|-------------------|-----|
| Layer 1: Exact Pattern Match | T₁ Lexical | Maps natural verbs → AST operations |
| Layer 2: Fuzzy Match | T₁ Lexical | Tolerates misspelling, word variation |
| Layer 3: Auto-Correct | T₂ Syntactic | Fixes mechanical errors |
| Layer 4: Context Engine | T₄ Semantic | Resolves pronouns, infers types |
| Layer 5: Temporal Resolver | T₄ Semantic | Resolves relative references |
| Layer 6: i18n Library | T₁ + T₅ | Accepts non-English input |
| Layer 7: AI Resolver | T₁–T₄ | Final fallback for all deterministic dims |

The voice pipeline's Transcription Cleanup Layer absorbs T₅ (Representational). Together, the 7-layer Tolerance Chain + Transcription Cleanup eliminates all six transformation dimensions, driving CD toward zero.

### 11.2 Error Tolerance as a Design Principle

Traditional compilers are designed to reject invalid input. Lume's compiler is designed to accept imperfect input and resolve intent through progressive fallback. This paradigm inversion makes the compiler fundamentally compatible with noisy input sources — not just voice, but handwriting OCR, chat messages, informal specs, non-native English, and even machine-generated prompts.

We argue this represents a new class of compiler: the **intent-resolving compiler**, which sits between traditional syntax-checking compilers and AI code generators. It shares the determinism and reproducibility of compilers (via compile-lock files) while accepting the input flexibility of AI systems (via the Tolerance Chain).

### 11.3 Deterministic Compilation of Non-Deterministic Input

A fundamental challenge: speech input is non-deterministic. The same phrase may be transcribed differently by different engines, at different times, with different accents. Lume addresses this through:

- **Compile-lock files** — cache the resolution of each line
- **Security certificates** — SHA-256 hash proving the compilation chain is unmodified
- **Layer A/B separation** — deterministic pattern matching preferred; AI results cached

This establishes that deterministic build outputs are achievable even from non-deterministic inputs, provided the resolution path is cached.

### 11.4 Compiler-Level Security as a Novel Paradigm

The "certified at birth" paradigm — code that is provably security-verified from the moment it is compiled — has no precedent. Traditional security operates externally, after compilation, without intent awareness. Lume's Guardian Output Scanner operates during compilation, with full access to both the developer's natural language instruction and the generated AST node. This makes it uniquely capable of detecting:

- **Semantic camouflage** — individually innocent instructions with dangerous combined intent
- **Natural language injection** — runtime data that could be misinterpreted as instructions
- **Intent-aware risk assessment** — distinguishing "delete expired sessions" (routine cleanup) from "delete all user records" (mass destruction) based on semantic meaning, not code patterns

### 11.5 Accessibility as Architecture

Voice-to-code is not merely convenient — it is architecturally significant for accessibility:

- Developers with RSI can code without typing
- Developers with mobility impairments can code with voice alone
- Developers who think better verbally can speak logic naturally
- No syntax to memorize — natural language IS the syntax
- Non-English speakers can program in their native language (Milestone 8)

This positions accessibility as an architectural consequence of the design, not an afterthought accommodation.

### 11.6 AI Agents and the Middleman Paradox

AI coding agents (Copilot, ChatGPT, Cursor) reduce some transformation dimensions but **increase the total chain length**:

```
Traditional:     Developer → Compiler                    (2 nodes, 1 hop)
AI-Assisted:     Developer → AI → Review → Compiler      (4 nodes, 3 hops)
Lume:            Developer → Compiler                    (2 nodes, 1 hop)
```

The AI is a **middleman**. It reduces T₁–T₃ but increases T₅ (composing effective prompts is its own skill) and T₆ (debugging AI-generated code requires understanding patterns you didn't choose). Net CD may decrease, but the **chain of trust** lengthens.

Lume eliminates the middleman. The compiler IS the understanding layer.

**Error Recovery: Chain of Custody Comparison**

| Failure Scenario | AI Agent (Copilot/ChatGPT) | Lume |
|-----------------|---------------------------|------|
| **Wrong code generated** | Developer must debug code they didn't write (High CD) | Compiler stops and asks for clarification (Zero Silent Errors) |
| **Subtle logic error** | AI passes syntax but fails at runtime; developer traces unfamiliar patterns | Semantic scanner catches intent mismatch at compile time |
| **Ambiguous intent** | AI guesses silently; developer may never know | Compiler emits DisambiguationRequired; refuses to proceed |
| **Security vulnerability** | Ships to production; discovered days/weeks later by external scanners | Guardian Scanner blocks compilation; vulnerability never enters codebase |
| **Regression detection** | Developer must manually verify correctness | Resolution Manifest locks mappings; drift detected automatically |

**The critical distinction:** AI agents fail *silently* — the human must find the mistake in code they didn't write (maximum cognitive distance). Lume fails *loudly* — the compiler refuses to produce output until the ambiguity is resolved (zero cognitive distance).

This justifies the T₆ (meta-cognitive) weight in the CD formula: debugging AI-generated code requires reverse-engineering the AI's thought process, a uniquely taxing cognitive operation that Lume eliminates entirely.

### 11.7 Ambiguity Resolution Protocol and the Resolution Manifest

The single biggest threat to Lume's credibility is **non-determinism**. If "get the users" compiles to `SELECT * FROM users` today but the AI model updates tomorrow and produces `DELETE FROM users`, the language fails.

**Canonical Lume Syntax (CLS):**

Every English-mode instruction, once resolved, maps to a **Canonical Lume Syntax** expression — a deterministic intermediate representation independent of AI model version, tolerance chain weights, or runtime environment.

```
// English input:
get all the users who signed up this month

// Canonical Lume Syntax (CLS):
QUERY users WHERE created_at >= MONTH_START(CURRENT_DATE)

// Generated JavaScript:
const result = await db.query('SELECT * FROM users WHERE created_at >= ...');
```

**The Resolution Manifest (`lume-lock.json`):**

```json
{
  "manifestVersion": "1.0",
  "compiler": "lume@0.4.2",
  "entries": [
    {
      "line": 1,
      "source": "get all the users who signed up this month",
      "sourceType": "text",
      "cls": "QUERY users WHERE created_at >= MONTH_START(CURRENT_DATE)",
      "resolvedBy": "ExactPatternMatch",
      "confidence": 0.97,
      "astHash": "sha256:a3f8b2c1...",
      "outputHash": "sha256:9e4d1f0a..."
    }
  ]
}
```

**Voice-Specific Guarantees:**

If the input is voice, the manifest stores the **cleaned text**, not raw audio:

```json
{
  "sourceType": "voice",
  "rawTranscription": "get all the users who signed up this month uhh",
  "cleanedText": "get all the users who signed up this month",
  "cleanupApplied": ["filler_removal"],
  "cls": "QUERY users WHERE created_at >= MONTH_START(CURRENT_DATE)"
}
```

This ensures builds are **reproducible 10 years from now** — even if the voice engine changes, the manifest preserves the exact cleaned input and CLS.

**Determinism Guarantees:**

| Property | Mechanism |
|----------|----------|
| Same text → same AST | CLS deterministic; manifest locks mapping |
| Same voice → same AST | Cleaned text stored; recompilation uses text |
| AI model updates | Layer B results cached in manifest |
| Compiler version changes | Manifest records version; warnings on mismatch |
| Drift detection | `lume verify` compares current vs. manifest |

### 11.8 Review Mode — HCI Transparency Layer

Lume provides a **Review Mode** where the compiler shows the developer exactly what it understood before executing:

```
$ lume compile app.lume --review

  Line 1: "get all the users who signed up this month"
  ├─ Intent: QUERY on collection 'users'
  ├─ Filter: created_at >= start of current month
  ├─ Resolved by: ExactPatternMatch (confidence: 0.97)
  └─ Output: const result = await db.query('SELECT * ...');
  
  ✓ Approve?  [y]es / [n]o / [e]dit
```

No code is emitted until the developer confirms each resolution. This provides human-in-the-loop verification without adding cognitive distance — the developer reviews the compiler's understanding in plain English, not in generated code.

### 11.9 DOM Intent Model — Cognitive Distance Applied to UI

Traditional frontend development requires learning HTML, CSS, JavaScript DOM APIs, and often a framework (React, Vue, etc.). Each layer adds transformation dimensions:

```
Designer's Intent → HTML structure → CSS styling → JS behavior → Framework abstractions
                  T₁ (Lexical)    T₂ (Syntactic)  T₃ (Structural)  T₅ (Representational)
```

Lume collapses this entire chain. The `dom` standard library module allows developers to express UI intent directly:

```lume
dom.create("section", {
  className: "glass-card",
  children: [
    dom.create("h2", { text: "Welcome", className: "gradient-text" }),
    dom.create("p", { text: "Built entirely with Lume" })
  ]
})
```

With `dom.inject_css()`, `dom.animate()`, `dom.reveal_on_scroll()`, and `dom.on()`, the entire frontend stack — structure, styling, animation, and interactivity — is expressed in Lume syntax. No HTML files, no CSS preprocessors, no build tools. The compiled output is a single browser-ready JavaScript file via `lume bundle --target=browser`.

**CD Mapping for UI Development:**

| Dimension | Traditional Web Dev | Lume DOM Model |
|-----------|-------------------|----------------|
| T₁ (Lexical) | HTML tags, CSS selectors | `dom.create(tag, opts)` |
| T₂ (Syntactic) | CSS property syntax | `styles: { color: "#06b6d4" }` |
| T₃ (Structural) | Component tree, state management | `dom.mount()`, `state.reactive()` |
| T₅ (Representational) | Framework abstractions (JSX, hooks) | None — direct DOM |
| T₆ (Meta-cognitive) | Debugging React re-renders, hook deps | `state.bind()` — explicit reactivity |

### 11.10 Verbal State Machines

The `state` standard library module introduces declarative state machines and reactive values as first-class primitives:

```lume
let page_state = state.machine({
  initial: "loading",
  states: {
    loading: { on: { LOADED: "ready", ERROR: "failed" } },
    ready:   { on: { REFRESH: "loading" } },
    failed:  { on: { RETRY: "loading" } }
  }
})

page_state.send("LOADED")
show page_state.current  // → "ready"
```

Reactive values provide lightweight observability without framework overhead:

```lume
let counter = state.reactive(0)
counter.bind(dom.select("#counter-display"))  // Auto-updates on change
counter.set(counter.get() + 1)                // UI updates automatically
```

Combined with English Mode, state transitions will be expressible verbally (future milestone), eliminating T₃ (structural) and T₄ (semantic) distance for state management entirely.

### 11.11 Collaborative Intent — Multi-Developer Compilation (Roadmap)

Milestone 12 envisions **collaborative compilation** — multiple developers writing Lume simultaneously, with the compiler resolving conflicting intents at the semantic level rather than the text level:

```
Developer A: "add a login form to the header"
Developer B: "remove the header and use a sidebar"

⚠ ConflictDetected:
  Developer A references "header" (line 3)
  Developer B removes "header" (line 5)
  Resolution required before compilation.
  Options:
    (a) Keep header + login form [Developer A's intent]
    (b) Replace header with sidebar + login form [Merge]
    (c) Reject — ask both developers to clarify
```

**Key Design Principles:**
- Intent-level conflict detection (not just text-level merge conflicts)
- The compiler understands WHAT each developer wants, not just WHAT they typed
- Conflicts are expressed in natural language, not diff hunks
- Resolution preserves the Context Stack for both developers
- The Resolution Manifest supports multi-author entries and collaborative compile-lock files

### 11.12 Recency-Frequency-Type (RFT) Model for Anaphora Resolution

Building on the Context Stack (§4.10), the RFT model enhances pronoun resolution with three-dimensional scoring:

```
Score(entity) = α·Recency(entity) + β·Frequency(entity) + γ·TypeMatch(entity, verb)

Where:
  α = 0.5  (most recent reference carries highest weight)
  β = 0.3  (frequently-referenced entities are preferred)
  γ = 0.2  (type compatibility acts as a filter)
```

**Recency:** Tracks the last 5 referenced entities in a sliding window, with exponential decay. **Frequency:** Weights entities by total usage count within the current scope. **Type Matching:** Cross-references action verbs with variable types — "delete" is valid for Collection/File/Record but not Boolean/Number. If the highest-scoring entity has TypeMatch = 0, the compiler triggers `DisambiguationRequired` rather than guessing. This positions Lume as a **Contextual Anchor** system.

### 11.13 Formal Experimental Design

To provide empirical proof that Lume minimizes Cognitive Distance, we propose three controlled studies:

**Study A — Task Completion Time (TCT):** Measure Intent-to-Execution speed across four groups: Python (manual), Python + GitHub Copilot, Lume English Mode (text), and Lume Voice Mode. Task: build a CRUD API. Hypothesis: Lume reduces TCT by 40-60% vs. Python, 20-30% vs. Copilot.

**Study B — Silent Error Rate:** Give participants deliberately ambiguous prompts. Measure how many times Copilot generates wrong code silently vs. how many times Lume triggers `DisambiguationRequired`. Hypothesis: Lume produces 0 silent errors; Copilot's silent error rate scales with prompt ambiguity.

**Study C — NASA-TLX (Hart & Staveland, 1988):** Subjective cognitive load measurement. Hypothesis: as CD → 0, all NASA-TLX subscales (Mental Demand, Frustration, Effort, Performance) trend toward minimum, validating the Dissonance Hypothesis.

### 11.14 Semantic Invariant Certificates — Full-Chain Integrity

The security certificate must bind the entire compilation chain:

```
Certificate = SHA-256(Input_English + Resolved_AST + Compiled_JavaScript)
```

This creates a tamper-evident chain: modifying any of the three artifacts invalidates the certificate. The certificate is embedded in compiled output:

```javascript
// LUME-CERT: sha256:a3f8b2c1... | Intent: QUERY | Risk: LOW | Chain: VALID
const result = await db.query('SELECT * FROM users');
```

**CI/CD Headless Policy:** In CI/CD environments, any instruction with confidence C < 0.85 triggers a hard `RESOLUTION_ERROR` rather than a best-guess. Interactive mode: 0.6 < C < 0.85 → pause for human disambiguation; C ≥ 0.85 → auto-resolve. Configure via `lume build --headless --min-confidence=0.85`.

### 11.15 Auditory Mode — Fully Hands-Free Programming

Lume's voice pipeline provides Voice → Text → Code. Auditory Mode completes the loop with **compiler-to-developer speech output** via Web Speech API (`SpeechSynthesis`), making programming entirely auditory:

```
Developer (speaks): "Get all the users who signed up this month"
Lume (speaks back): "I understood: query the users collection,
  filtering by signup date in the current month.
  Confidence: 97 percent. Shall I compile?"
Developer (speaks): "Yes"
Lume (speaks back): "Compiled successfully."
```

This makes Lume the **first programming language usable with eyes closed** — fully hands-free, fully accessible. CD for Auditory Mode = 0 across all dimensions. For developers with visual impairments, motor disabilities, or hands-occupied scenarios, Auditory Mode transforms programming from a keyboard-dependent activity to a conversational one.

---

## 12. Limitations and Future Work

### 12.1 Current Limitations

1. **Accent variation** — speech-to-text accuracy varies significantly across accents and dialects, affecting voice pipeline reliability
2. **Domain-specific jargon** — the pattern library and auto-correct dictionary may not cover specialized terminology in niche domains (bioinformatics, quantum computing, etc.)
3. **Ambiguity ceiling** — some natural language instructions are genuinely ambiguous even to humans; the Interactive Clarification Mode mitigates but cannot eliminate this
4. **AI resolution cost** — Layer B resolution requires API calls, introducing latency and monetary cost; the batching system and compile-lock caching mitigate this
5. **JavaScript target limitation** — Lume currently transpiles only to JavaScript; additional target languages would broaden applicability

### 12.2 Future Work

1. **Streaming compilation** — real-time AST generation as voice input is received, without waiting for instruction boundaries
2. **Multi-speaker collaboration** — multiple developers speaking simultaneously, each recognized and tracked
3. **Handwriting OCR input** — extending the Transcription Cleanup Layer paradigm to handwritten input
4. **Pictographic input mode** — single-symbol input representing entire programming concepts, paired with a custom developer keyboard
5. **Agent-to-agent communication** — Lume scripts as a shared protocol for inter-agent communication across distributed systems
6. **Formal verification integration** — extending the security certificate to include formal proofs of specific properties
7. **Self-modifying programs** — controlled self-modification with safety guardrails (type signature preservation, intent block validation, mutation depth limits)
8. **Adaptive Voice Profiles** — per-user dialect learning inserted at Layer 1.5 of the Tolerance Chain. The system records each user's unique colloquialisms ("gimme" → "get," "toss" → "delete"), accent-specific transcription artifacts, and filler words. Candidate mappings auto-promote to confirmed status after 5 consistent uses. This transforms the compiler from a static tool into a personalized interaction partner: the more a user programs with Lume, the better the compiler understands them. Partially implemented as `voice-profile.js` in `src/intent-resolver/`. Includes a Dialect Confidence score (sigmoid-based, asymptotic to 1.0) and integration with the Self-Evolving runtime layer for long-term pattern analysis.

---

## 13. Conclusion

We have presented Lume, an AI-native programming language that fundamentally reconceives the relationship between developer intent and compiled output. By designing the compiler to accept imprecise natural language as valid source code — rather than demanding exact syntactic conformity — we achieve three capabilities as architectural consequences:

1. **Voice-to-code** at the compiler level, not the IDE level
2. **Intent-aware security scanning** that produces tamper-evident certificates — "certified at birth"
3. **Near-zero cognitive distance** between thought and compiled code

The Tolerance Chain (7-layer progressive fallback), the Guardian Output Scanner (live AST-level security), the Transcription Cleanup Layer (7-step voice normalization), and the compile-lock system (deterministic reproducibility from non-deterministic input) together constitute a new category of compiler — the **intent-resolving compiler**.

The cognitive dissonance that every programmer experiences daily — thinking in one language, forced to act in another — is not an inevitable consequence of programming. It is a consequence of compilers that refuse to meet the developer halfway. Lume eliminates the distance.

Other tools add an AI between you and your code. Lume removes the code between you and your machine.

---

## References

Festinger, L. (1957). *A Theory of Cognitive Dissonance.* Stanford University Press.

Winograd, T. (1972). Understanding natural language. *Cognitive Psychology*, 3(1), 1-191.

Chen, M., et al. (2021). Evaluating large language models trained on code. *arXiv preprint arXiv:2107.03374.*

Li, Y., et al. (2022). Competition-level code generation with AlphaCode. *Science*, 378(6624), 1092-1097.

Radford, A., et al. (2023). Robust speech recognition via large-scale weak supervision (Whisper). *Proceedings of ICML 2023.*

Myers, B. A., Ko, A. J., & Burnett, M. M. (2006). Invited research overview: end-user programming. *CHI '06 Extended Abstracts on Human Factors in Computing Systems.*

Green, T. R. G. (1989). Cognitive dimensions of notations. *People and Computers V*, 443-460.

Gulwani, S., Polozov, O., & Singh, R. (2017). Program synthesis. *Foundations and Trends in Programming Languages*, 4(1-2), 1-119.

Ko, A. J., Abraham, R., Beckwith, L., et al. (2011). The state of the art in end-user software engineering. *ACM Computing Surveys*, 43(3), 1-44.

---

## Appendix A: Repository and Deployment

| Item | Value |
|------|-------|
| Source repository | github.com/cryptocreeper94-sudo/lume |
| Language | JavaScript (Node.js) |
| Primary domain | lume-lang.com |
| Secondary domain | lume-lang.org |
| Backend | Express.js + PostgreSQL |
| Frontend | React (Vite) |
| Version | 0.8.0 |
| License | Open source |
| Support | team@dwsc.io |
| Launch | August 23, 2026 CST |
| Ecosystem | App #35 of 35 (Trust Layer / DarkWave) |

---

## Appendix B: Complete CLI Command Reference

**Build and Run:**

| Command | Description |
|---------|-------------|
| `lume build <file>` | Compile .lume to JavaScript |
| `lume build --bundle` | Single-file JS output |
| `lume build --compile` | Standalone binary via Bun |
| `lume build --fresh` | Re-resolve all (ignore compile-lock) |
| `lume build --check` | Verify without writing output |
| `lume build --sourcemap` | Generate source maps |
| `lume build --target <platform>` | Cross-compile (linux, macos, windows, wasm) |
| `lume run <file>` | Compile and execute |
| `lume run --sandbox` | Force sandbox mode |
| `lume run --trusted` | Skip sandbox for locked programs |
| `lume repl` | Interactive REPL |
| `lume repl --mode english` | English Mode REPL |

**Testing:**

| Command | Description |
|---------|-------------|
| `lume test` | Run all tests (intent blocks + test files) |
| `lume test --filter <name>` | Filter tests by name |
| `lume test --watch` | Re-run on file changes |
| `lume test --coverage` | Generate test coverage report |

**Voice:**

| Command | Description |
|---------|-------------|
| `lume voice` | Interactive voice coding (batch mode) |
| `lume voice --live` | Compile each instruction immediately |
| `lume voice --review` | Review transcription before compiling |
| `lume voice --engine whisper` | Use Whisper API for transcription |
| `lume voice --output <file>` | Save transcription to named .lume file |
| `lume listen` | CLI voice capture |

**Code Intelligence:**

| Command | Description |
|---------|-------------|
| `lume explain <file>` | Explain code in plain language |
| `lume explain --lang <language>` | Explain in specified human language |
| `lume fix <file>` | AI-powered error fix |
| `lume lint <file>` | Lint for clarity and ambiguity |
| `lume lint --strict` | Maximum lint strictness |
| `lume canonicalize <file>` | Normalize English instructions to canonical form |
| `lume docs <file>` | Generate documentation from comments |
| `lume debug <file>` | Enhanced error catching |
| `lume debug --step` | Step-through debugging mode |

**Project Management:**

| Command | Description |
|---------|-------------|
| `lume init` | Initialize a new Lume project |
| `lume init --hooks` | Initialize with Git hooks |
| `lume create <file>` | Generate full-stack app from description |
| `lume create --preview` | Preview generated app before writing |
| `lume install <pkg>` | Install and register npm package |
| `lume config` | View/set project configuration |
| `lume config alias <name> <expansion>` | Add custom auto-correct alias |
| `lume upgrade` | Upgrade pattern library version |

**Security:**

| Command | Description |
|---------|-------------|
| `lume verify --hash <hash>` | Verify security certificate |
| `lume verify --file <file>` | Verify certificate in compiled file |

**Self-Sustaining Runtime (Milestone 6):**

| Command | Description |
|---------|-------------|
| `lume monitor` | Real-time monitoring dashboard |
| `lume heal status` | View self-healing status and recovery log |
| `lume optimize suggest` | Show AI optimization suggestions |
| `lume evolve status` | View self-evolution daemon status |

**Pattern Management:**

| Command | Description |
|---------|-------------|
| `lume patterns list` | List all patterns in current library version |
| `lume patterns sync` | Sync community pattern updates |
| `lume patterns contribute` | Submit a pattern to the community library |

---

## Appendix C: Monetization

- Compiler + Layer A (pattern matching): free, forever
- Layer B (AI resolution): 100 calls/month free; unlimited Pro $15/month; Team $12/seat/month; Enterprise custom

---

*Submitted for consideration. Correspondence: team@dwsc.io*
