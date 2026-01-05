# LSP vs Semantic Search: Live Test Comparison

**Date**: 2025-01-05
**Index Status**: 270 chunks | gemini (768 dims) | Fresh (22m ago)
**Repo**: opencode-semanthicc

---

## Test 1: Exact Symbol Lookup - `saveEmbeddingConfig`

**Query**: Find the function `saveEmbeddingConfig`

### LSP Result:
```
serena_find_symbol("saveEmbeddingConfig")
→ src/embeddings/config-store.ts lines 53-73 (Function)
```
- **Precision**: Exact function boundaries
- **Speed**: Instant
- **Noise**: Zero

### Semantic Result:
```
semanthicc search "saveEmbeddingConfig" focus:code limit:5
→ #1: src/embeddings/config-store.ts (lines 1-79, whole chunk)
→ #2: src/config.ts (lines 90-135)
→ #3: src/db/schema.sql (lines 92-95)
→ #4: src/embeddings/config-store.ts (lines 81-153)
→ #5: src/config.ts (lines 1-88)
```
- **Precision**: Correct file found, but chunk-level (not function boundaries)
- **Speed**: ~200ms
- **Noise**: 4 additional results (related but not exact)

### Verdict: **LSP WINS** ✅

**Reasoning**: For exact symbol lookup, LSP provides precise line numbers and zero noise. Semantic search finds the right file but returns the entire chunk (lines 1-79) instead of just the function (lines 53-73). The 0.0% match score indicates semantic is doing vector similarity, not exact text match - wasteful for known symbol names.

**Use Case Guidance**: When you know the exact symbol name → always use LSP.

---

## Test 2: Partial Symbol Match - `get*` functions

**Query**: Find all functions starting with "get"

### LSP Result:
```
serena_find_symbol("get", substring_matching=true, include_kinds=[12,6])
→ 76 functions found across entire codebase
```
Examples:
- `getDb` → src/db/index.ts:53-74
- `getStatus` → src/status.ts:49-133
- `getEmbeddingConfig` → src/config.ts:84-87
- `getLanceDb` → src/lance/connection.ts:22-38
- `getStoredEmbeddingConfig` → src/embeddings/config-store.ts:35-51

- **Precision**: Exact function names + line numbers
- **Coverage**: ALL 76 `get*` functions in codebase
- **Noise**: Includes test callbacks (noisy but complete)

### Semantic Result:
```
semanthicc search "get functions that retrieve data" focus:code limit:10
→ #1: docs/edge-cases-testing.md (WRONG - docs not code!)
→ #2: src/lance/file-tracker.ts (lines 1-94)
→ #3: src/search/synonyms.ts (lines 1-54)
→ #4: src/dashboard/api.ts (lines 1-30)
→ ...other mixed results
```
- **Precision**: Chunk-level, not function-level
- **Coverage**: Only ~10 results vs 76 actual functions
- **Noise**: Docs ranked #1 despite `focus:code`

### Verdict: **LSP WINS** ✅

**Reasoning**: 
1. LSP found ALL 76 `get*` functions with exact locations
2. Semantic returned docs as #1 result (wrong!) even with `focus:code`
3. Semantic only returned ~10 chunks vs 76 actual functions
4. LSP includes test functions too (complete vs selective)

**Surprise Finding**: `focus:code` didn't prevent docs from ranking #1 - potential bug or weak boosting.

**Use Case Guidance**: For pattern-based symbol discovery → LSP substring matching is far superior.

---

## Test 3: Conceptual Search - 'embedding dimension validation'

**Query**: "how does embedding dimension validation work" (no specific function name known)

### LSP Result:
```
serena_find_symbol("validate", substring_matching=true)
→ Only finds if you GUESS the right word in the function name
```
Without knowing the function is called `validateEmbeddingConfig`, LSP requires:
1. Trial-and-error keyword guessing
2. Or browsing symbol overviews manually

### Semantic Result:
```
semanthicc search "how does embedding dimension validation work" focus:code
→ #1: src/embeddings/config-store.ts (lines 81-153) - validateEmbeddingConfig function
→ #2: specs/semantic-search.md (spec docs)
→ #3: docs/edge-cases-testing.md (test scenarios for dimension mismatch)
→ #5: src/embeddings/config-store.test.ts (tests for validateEmbeddingConfig)
```
- **Precision**: Found the EXACT function and its tests!
- **Context**: Also found related docs and specs
- **Understanding**: Query had "dimension validation" → matched "validateEmbeddingConfig"

### Verdict: **SEMANTIC WINS** ✅

**Reasoning**: 
1. Semantic understood intent: "dimension validation" → `validateEmbeddingConfig`
2. Also surfaced related tests and docs (valuable context)
3. LSP would require knowing `validateEmbeddingConfig` exists first
4. For conceptual queries where you describe WHAT not WHICH, semantic excels

**Critical Insight**: The power of semantic search is query-to-intent mapping:
- "dimension validation" (user intent) → `validateEmbeddingConfig` (actual code)
- LSP can't bridge this gap without exact symbol names

**Use Case Guidance**: Don't know the function name? Describe what it does → use Semantic.

---

## Test 4: Find References - 'where is walkProject used'

**Query**: Find all places that call `walkProject`

### LSP Result:
```
serena_find_referencing_symbols("walkProject", "src/indexer/walker.ts")
→ 8 references found with exact context:
```
| File | Line | Context |
|------|------|---------|
| src/indexer/indexer.ts | 6 | `import { walkProject } from "./walker"` |
| src/indexer/indexer.ts | 62 | `const files = walkProject(projectPath, { maxFiles })` |
| src/status.ts | 2 | `import { walkProject } from "./indexer/walker"` |
| src/status.ts | 196 | `for await (const file of walkProject(projectPath))` |
| src/indexer/indexer.test.ts | 7 | `import { walkProject } from "./walker"` |
| src/indexer/indexer.test.ts | 115 | `const files = walkProject(testDir)` |
| src/indexer/indexer.test.ts | 124 | `const files = walkProject(testDir)` |
| src/indexer/indexer.test.ts | 130 | `const files = walkProject(testDir, { maxFiles: 1 })` |

- **Precision**: EXACT call sites with surrounding code
- **Completeness**: ALL 8 references
- **Noise**: Zero false positives

### Semantic Result:
```
semanthicc search "walkProject function usage callers" focus:code
→ #1: src/indexer/walker.ts (definition, not usage!)
→ #2: design.md (unrelated SQL)
→ #3: src/hooks/project-detect.ts (no walkProject call!)
→ #5: src/indexer/indexer.ts (correct - actual caller)
→ ...most results don't contain walkProject at all
```
- **Precision**: Only 2/10 results actually reference `walkProject`
- **Completeness**: Missing 6 of 8 actual call sites
- **Noise**: 80% false positives

### Verdict: **LSP WINS** ✅✅✅

**Reasoning**: 
1. LSP found ALL 8 references with exact line numbers and context
2. Semantic returned mostly irrelevant results (80% noise)
3. Semantic found the definition (#1) instead of usages
4. For "find all callers of X", LSP is the ONLY reliable tool

**Critical Insight**: Semantic search cannot do graph traversal (who-calls-what). It matches semantically similar TEXT, not call relationships.

**Use Case Guidance**: "Where is X used?" / "Who calls X?" → ALWAYS use LSP find_referencing_symbols.

---

## Test 5: Comment/TODO Search - 'deprecated functions'

**Query**: Find code with comments about migrations, database version updates

### LSP Result:
```
serena_find_symbol("deprecated", substring_matching=true)
→ [] (empty - LSP only knows symbols, not comments)

serena_search_for_pattern("TODO") 
→ Error: path issue on Windows
```
LSP cannot search comment content - comments are not symbols.

Fallback: `grep "// Migration"` → Found 3 matches (but that's grep, not LSP)

### Semantic Result:
```
semanthicc search "comments about migration database version update" focus:code
→ #1: .github/issues/v0.7.0-lancedb-migration.md ✅ (migration docs)
→ #2: docs/patchlog.md (mentions getDb, DB connection, migration)
→ #6: src/db/index.ts ✅ (contains "// Migration: add keywords column if missing")
→ #7: design.md (SQL schema context)
→ #8: src/db/schema.sql (schema context)
```
- **Precision**: Found inline migration comments in db/index.ts!
- **Context**: Also found related docs about migrations
- **Understanding**: Connected "migration" concept across code AND docs

### Verdict: **SEMANTIC WINS** ✅

**Reasoning**: 
1. LSP CANNOT search comment content - it only knows symbols
2. Semantic indexed comments as part of code chunks
3. Found both inline comments AND documentation
4. Cross-type search (code + docs) is valuable for understanding

**Limitation Observed**: Semantic returned markdown first (#1) despite `focus:code`. This suggests:
- Markdown about migrations scored higher than code with migration comments
- The `focus:code` boost may be too weak

**Use Case Guidance**: Searching for comments, TODOs, annotations → Semantic (LSP blind here).

---

## Test 6: DSL in Strings - SQL query or regex pattern

**Query**: Find SQL queries with SELECT, WHERE, FROM in the codebase

### LSP Result:
```
serena_find_symbol("SELECT", substring_matching=true)
→ [] (empty - SQL in strings is not a symbol)
```
LSP only indexes language symbols. SQL embedded in template strings is invisible.

### Semantic Result:
```
semanthicc search "SQL query SELECT FROM WHERE database statement" focus:code
→ #1: src/hooks/similarity.ts (uses db.prepare with SQL)
→ #2: specs/heuristics.md (SQL examples in specification)
→ #3: specs/schema.md (UPDATE queries with WHERE)
→ #4: src/heuristics/repository.ts (SQL queries in code)
→ #6: src/db/db.test.ts (db.exec with INSERT/SELECT)
→ #7: TESTS.md (SQL injection security test cases!)
```
- **Precision**: Found real SQL queries in repository.ts, similarity.ts!
- **Context**: Also found specs with SQL examples
- **Surprise**: Found SQL injection security test docs (#7)

### Verdict: **SEMANTIC WINS** ✅

**Reasoning**: 
1. LSP CANNOT see content inside strings - SQL is invisible to it
2. Semantic indexed the string content as part of chunks
3. Found 6 files with SQL queries vs 0 from LSP
4. Also surfaced related security tests (bonus discovery)

**Key Insight**: Embedded DSLs (SQL, GraphQL, regex) live in strings, which LSP ignores. Semantic search treats all text equally.

**Use Case Guidance**: Finding SQL, GraphQL, regex, shell commands in strings → Semantic only.

---

## Test 7: Config File Search - 'tsconfig compiler options'

**Query**: Find tsconfig.json and its compiler options

### LSP Result:
```
serena_get_symbols_overview("tsconfig.json")
→ [] (empty - JSON files have no symbols!)

serena_find_symbol("compilerOptions", substring_matching=true)
→ [] (empty - JSON keys are not TypeScript symbols)
```
LSP doesn't parse JSON files for symbols. They're invisible.

### Semantic Result:
```
semanthicc search "tsconfig compiler options strict module resolution"
→ #1: tsconfig.json ✅ (root config!)
→ #2: src/dashboard/ui/tsconfig.json ✅ (nested config!)
→ #3: src/log-config.ts (config-related but not tsconfig)
→ #4-5: src/config.ts (general config handling)
```
- **Precision**: Found BOTH tsconfig.json files in the project!
- **Content**: Returned actual compilerOptions contents
- **Related**: Also surfaced config.ts (relevant context)

### Verdict: **SEMANTIC WINS** ✅

**Reasoning**: 
1. LSP cannot index JSON files as symbols - only code
2. Semantic indexed tsconfig.json as full text
3. Found both root and nested (dashboard/ui) tsconfig files
4. Bonus: also surfaced related config.ts module

**Critical Insight**: Config files (JSON, YAML, TOML, .env) are invisible to LSP. Semantic sees everything as text.

**Use Case Guidance**: Searching config files, package.json, .env, YAML → Semantic only.

---

## Test 8: Error Handling - 'how errors are caught'

**Query**: Find error handling patterns (try/catch, error detection)

### LSP Result:
```
serena_find_symbol("Error", substring_matching=true)
→ 21 symbols found:
```
| Symbol | File |
|--------|------|
| `EmbeddingConfigMismatchError` (Class) | src/embeddings/config-store.ts |
| `DuplicateMemoryError` (Class) | src/heuristics/repository.ts |
| `isToolError` (Function) | src/hooks/error-detect.ts |
| `shouldCaptureError` (Function) | src/hooks/passive-learner.ts |
| `isError` properties (7x) | Various test files |

- **Precision**: Found error CLASSES and error DETECTION functions
- **Limitation**: Cannot find try/catch blocks (not symbols)

### Semantic Result:
```
semanthicc search "how errors are caught exception handling try catch pattern" focus:code
→ #1: src/hooks/error-detect.ts ✅ (ERROR_PATTERNS regex array!)
→ #2: src/hooks/error-detect.test.ts (isToolError tests)
→ #3-4: src/hooks/passive-filtering.test.ts (shouldCaptureError tests)
→ #5: src/hooks/passive-learner.ts (error capture logic)
→ #8: src/hooks/similarity.test.ts (findSimilarFailures)
```
- **Precision**: Found error PATTERNS, detection LOGIC, and tests
- **Context**: Shows complete error handling subsystem
- **Conceptual**: "try catch" → matched error detection even though no literal "try/catch"

### Verdict: **TIE - Different Strengths** 🤝

**Reasoning**: 
1. **LSP** found error-related SYMBOLS (classes, functions): Great for "what error types exist?"
2. **Semantic** found error HANDLING LOGIC: Great for "how do we handle errors?"
3. LSP precise but narrow (only named symbols)
4. Semantic broader but includes tests mixed in

**Complementary Use Case**:
- "What error classes do we have?" → LSP `find_symbol("Error")`
- "How does error detection work?" → Semantic conceptual search

**Use Case Guidance**: Error classes/types → LSP. Error handling patterns → Semantic. Best to use both.

---

## Test 9: Cross-file Flow - 'indexing pipeline from start to end'

**Query**: Understand the indexing workflow from file discovery to embedding creation

### LSP Result:
```
serena_find_symbol("index", relative_path="src/indexer", substring_matching=true)
→ 13 symbols found:
```
| Symbol | File | Purpose |
|--------|------|---------|
| `indexProject` (Function) | src/indexer/indexer.ts | Main entry point |
| `Chunk/index` (Property) | src/indexer/chunker.ts | Chunk index |
| `splitIntoAstChunks` | src/indexer/ast-chunker.ts | AST chunking |
| Test callbacks (4x) | *.test.ts | Integration tests |

- **Precision**: Found the key functions
- **Limitation**: Shows PIECES, not the FLOW between them
- **Missing**: Doesn't show how `indexProject` → `walkProject` → `splitIntoChunks` → `embedText` connects

### Semantic Result:
```
semanthicc search "indexing pipeline workflow file processing embedding creation end to end" focus:code
→ #1: src/indexer/indexer.ts (lines 72-166) ✅ - THE MAIN LOOP!
→ #3: src/lance/embeddings.ts - embedding storage
→ #5: src/indexer/indexer.ts (lines 1-70) - imports & setup
→ #7: specs/semantic-search.md - architecture overview
→ #8-10: .github/issues/v0.7.0-lancedb-migration.md - explains why & design
```
- **Context**: Found the CORE LOOP (lines 72-166) with batching, progress, abort handling
- **Related**: Also surfaced embedding storage and migration docs
- **Narrative**: Query "end to end" matched the flow-describing chunks

### Verdict: **SEMANTIC WINS** ✅

**Reasoning**: 
1. LSP found isolated symbols - "here are the function names"
2. Semantic found the actual IMPLEMENTATION of the pipeline (the for loop with batching)
3. Cross-file flows need CONCEPTUAL understanding, not just symbol names
4. Semantic also surfaced specs explaining the design intent

**Key Insight**: Understanding "how things work together" requires reading implementation, not just names. Semantic surfaces the narrative chunks.

**Use Case Guidance**: Symbol discovery → LSP. Understanding workflows/flows → Semantic.

---

## Test 10: Anonymous/Arrow Functions - 'callback handlers'

**Query**: Find anonymous arrow functions used as callbacks

### LSP Result:
```
serena_find_symbol("callback", substring_matching=true)
→ 330+ anonymous callbacks found!
```
Examples (sampling from ~330 results):
| Symbol Path | File | Line |
|-------------|------|------|
| `describe(...) callback` | Various *.test.ts | Many |
| `memories.filter() callback` | src/dashboard/api.ts | 77-78 |
| `findTopK/sort() callback` | src/embeddings/similarity.ts | 27 |
| `parseGitignore/filter() callback` | src/indexer/walker.ts | 18 |
| `expandQuery/forEach() callback[0]` | src/search/synonyms.ts | 38 |

- **Precision**: Found 330+ callbacks with EXACT locations
- **Naming**: LSP generated synthetic names like `describe(..) callback`
- **Exhaustive**: Found ALL callbacks in tests and production code

### Semantic Result:
```
semanthicc search "anonymous arrow function callback handler event listener" focus:code
→ #1: src/dashboard/ui/src/App.svelte (1 line only!)
→ #2: src/logger.ts 
→ #3: tsconfig.json (!? not even code)
→ #4-7: src/indexer/ast-chunker.test.ts (test files)
→ #9: src/hooks/passive-learner.ts
```
- **Precision**: Only returned ~10 chunks, not individual callbacks
- **Noise**: tsconfig.json ranked #3 (completely wrong)
- **Missing**: Didn't find most of the 330+ actual callbacks

### Verdict: **LSP WINS** ✅✅

**Reasoning**: 
1. LSP found 330+ callbacks with exact function boundaries
2. Semantic returned only ~10 mixed results, including tsconfig.json
3. LSP generates synthetic names for anonymous functions (impressive!)
4. For "find all X" queries, LSP comprehensive coverage beats semantic guessing

**Surprise**: TypeScript language server names anonymous callbacks with paths like `describe(...) callback/test(...) callback/files.some() callback` - useful for navigation!

**Use Case Guidance**: Finding anonymous functions → LSP (has synthetic naming for them).

---

## Test 11: Type Definitions - 'EmbeddingConfig interface'

**Query**: Find the EmbeddingConfig interface/type definition

### LSP Result:
```
serena_find_symbol("EmbeddingConfig", include_kinds=[11,5], include_body=true)
→ 2 interfaces found:
```
| Location | Body |
|----------|------|
| `src/config.ts:7-12` | `interface EmbeddingConfig { provider?, geminiApiKey?, geminiModel?, dimensions? }` |
| `src/dashboard/ui/src/types.ts:22-27` | `interface EmbeddingConfig { provider, geminiModel, dimensions, hasApiKey? }` |

- **Precision**: Exact interface bodies returned!
- **Complete**: Found BOTH definitions (main + UI types)
- **Actionable**: Lines 7-12, 22-27 - ready to navigate

### Semantic Result:
```
semanthicc search "EmbeddingConfig interface type definition" focus:code
→ #1: src/config.ts (lines 1-88) - whole chunk, interface somewhere in there
→ #2: src/embeddings/config-store.ts (imports EmbeddingConfig, not definition)
→ #3: src/embeddings/embed.ts (imports EmbeddingConfig, not definition)
→ #4: src/dashboard/ui/src/types.ts (lines 1-87) - correct but whole file
```
- **Precision**: Found correct files but as 88-line chunks
- **Noise**: config-store.ts and embed.ts only IMPORT the type
- **Missing**: Didn't distinguish between definitions vs imports

### Verdict: **LSP WINS** ✅

**Reasoning**: 
1. LSP found EXACTLY where the interface is defined (lines 7-12, 22-27)
2. LSP returned the BODY of the interface - ready to read
3. Semantic found files containing "EmbeddingConfig" but couldn't distinguish definition from import
4. For type lookup, LSP kind filtering (interface=11) is surgical

**Key Insight**: Semantic search can't distinguish between "defines X" vs "uses X". LSP's symbol kinds provide this.

**Use Case Guidance**: Type/interface definitions → LSP with kind filtering.

---

## Test 12: Test vs Production - 'chunker logic' (focus filtering)

**Query**: Find chunker implementation (production code vs tests)

### Semantic focus:code vs focus:tests:
```
semanthicc search "chunker split content into chunks" focus:code
→ #1: src/indexer/ast-chunker.ts (production) ✅
→ #2: docs/v1.7.0-roadmap.md (DOCS!)
→ #4: src/indexer/ast-chunker.test.ts (test file!)

semanthicc search "chunker split content into chunks" focus:tests  
→ EXACT SAME RESULTS! (no filtering difference)
```
- **Focus not working**: `focus:code` and `focus:tests` returned identical results
- **Docs still rank high**: Even with `focus:code`, docs ranked #2
- **BUG IDENTIFIED**: Focus parameter appears to have no effect

### LSP Result:
```
serena_find_symbol("splitInto", relative_path="src/indexer", substring_matching=true)
→ 2 production functions:
  - splitIntoAstChunks → ast-chunker.ts:28-73
  - splitIntoChunks → chunker.ts:40-76
```
No test files in result - path restriction worked perfectly.

### Verdict: **LSP WINS** ✅ (but exposes Semantic bug)

**Reasoning**: 
1. LSP path restriction cleanly isolates production from tests
2. Semantic `focus` parameter DOES NOT WORK - same results both ways
3. This is a **BUG** in semanthicc - focus should apply a file pattern filter

**Bug Report**: `focus:code` vs `focus:tests` produces identical results. Need to investigate LanceDB boosting or filter implementation.

**Use Case Guidance**: Filtering by file type (tests vs production) → LSP path restriction. Semantic focus is broken.

---

## Test 13: Vague Intent - 'make search faster'

**Query**: "make search faster" (vague optimization intent)

### LSP Result:
```
serena_find_symbol("faster", substring_matching=true) → []
serena_find_symbol("performance", substring_matching=true) → []
```
LSP found nothing - no symbols contain "faster" or "performance".

### Semantic Result:
```
semanthicc search "make search faster optimize performance speed improvement"
→ #1: docs/v1.6.0-planning.md (planning docs with effort/impact analysis!)
→ #3: specs/semantic-search.md (cosineSimilarity - THE hot path!)
→ #4: src/search/search.ts (searchCode function - entry point)
→ #6: src/lance/embeddings.ts (hybridSearch - vector operations)
→ #7: .github/issues/v0.5.0-improvements.md (improvement ideas!)
```
- **Relevance**: Found the ACTUAL search implementation
- **Context**: Also found planning docs with optimization ideas
- **Conceptual**: "make faster" → matched search, embeddings, hybrid

### Verdict: **SEMANTIC WINS** ✅✅

**Reasoning**: 
1. LSP cannot understand intent - "faster" isn't a symbol name
2. Semantic matched intent to implementation: "make search faster" → searchCode, hybridSearch, cosineSimilarity
3. Also surfaced historical planning docs (useful context)
4. For vague "I want to improve X" queries, only semantic search works

**Key Insight**: When the user describes a GOAL rather than a TARGET, semantic search is the only option.

**Use Case Guidance**: Vague improvement requests → Semantic. LSP needs concrete symbols.

---

## Test 14: Multi-word Technical - 'lancedb vector embedding hybrid search'

**Query**: "lancedb vector embedding hybrid search" (technical multi-keyword)

### LSP Result:
```
serena_find_symbol("hybrid", substring_matching=true)
→ hybridSearch → src/lance/embeddings.ts:111-195
```
- **Precision**: Found THE function
- **Limitation**: Only searched one keyword ("hybrid")

### Semantic Result:
```
semanthicc search "lancedb vector embedding hybrid search implementation"
→ #1: src/lance/embeddings.ts (searchVectors function - vector search)
→ #2: src/lance/embeddings.ts:1-84 (imports + EmbeddingRecord interface)
→ #3: .github/issues/v0.7.0-lancedb-migration.md (DESIGN DOC!)
→ #4: src/lance/embeddings.ts:119-196 (hybridSearch function!)
→ #7: src/lance/embeddings.ts (ensureFtsIndex - FTS for hybrid)
→ #8: src/search/search.ts (searchCode - main entry)
→ #9: design.md (Hybrid Retrieval architecture table!)
```
- **Coverage**: Found ENTIRE hybrid search system: searchVectors, hybridSearch, FTS, entry point
- **Context**: Migration docs explaining WHY we use LanceDB
- **Related**: Design doc with architecture overview

### Verdict: **SEMANTIC WINS** ✅✅

**Reasoning**: 
1. LSP found `hybridSearch` (correct!) but only ONE function
2. Semantic found the ENTIRE RELATED SYSTEM: 7+ relevant chunks
3. Multi-word technical queries benefit from semantic understanding
4. LSP would require multiple searches: "lance", "vector", "hybrid", "fts"
5. Semantic connected the concepts with ONE query

**Key Insight**: For complex technical queries with multiple related concepts, semantic search's vector similarity naturally finds related code. LSP would need N separate searches.

**Use Case Guidance**: Multi-concept technical queries → Semantic finds the system. LSP finds individual symbols.

---

## Test 15: Bug Hunting - 'null pointer or undefined access'

**Query**: Find potential null/undefined bugs and dangerous patterns

### LSP Result:
```
lsp_diagnostics("src/search/search.ts", severity="all")
→ "No diagnostics found"
```
- **Interpretation**: Code is currently type-safe (no TS errors)
- **Limitation**: Only finds TYPE errors, not logical bugs

### Semantic Result:
```
semanthicc search "null pointer undefined access potential bug dangerous optional chaining missing check"
→ #3: src/heuristics/repository.ts (getMemoryChain - runtime type checking!)
→ #4: TESTS.md (Security test cases - SQL injection, prompt injection)
→ #7: docs/edge-cases-testing.md (deleted file ghost results - edge case)
→ #10: src/hooks/passive-filtering.test.ts (TypeError tests!)
```
- **Found**: Runtime type checking logic in repository.ts
- **Found**: Security test scenarios in TESTS.md
- **Found**: Edge case documentation
- **Found**: Error pattern detection tests

### Verdict: **TIE - Different Purposes** 🤝

**Reasoning**: 
1. **LSP diagnostics**: Finds STATIC type errors in current code - none here (good!)
2. **Semantic search**: Finds code ABOUT error handling, tests for bugs, edge case docs
3. Neither finds "hidden bugs" - that requires runtime analysis or code review
4. Together they provide: static safety (LSP) + context about error patterns (Semantic)

**Key Insight**: 
- LSP: "Is this code type-safe?" (compiler-level)
- Semantic: "Where do we handle errors?" (pattern discovery)
- Neither is a bug FINDER, but semantic can surface error-handling code for review

**Use Case Guidance**: Type errors → LSP diagnostics. Error handling review → Semantic. Real bug hunting requires both + human review.

---

## Final Results Matrix

### Score Summary

| Test # | Query Type | LSP | Semantic | Winner |
|--------|------------|-----|----------|--------|
| 1 | Exact symbol lookup | ✅✅ | ⚠️ | **LSP** |
| 2 | Partial symbol match (`get*`) | ✅✅ | ❌ | **LSP** |
| 3 | Conceptual ("dimension validation") | ❌ | ✅✅ | **Semantic** |
| 4 | Find references (callers) | ✅✅✅ | ❌ | **LSP** |
| 5 | Comments/TODOs | ❌ | ✅ | **Semantic** |
| 6 | DSL in strings (SQL) | ❌ | ✅ | **Semantic** |
| 7 | Config files (JSON) | ❌ | ✅✅ | **Semantic** |
| 8 | Error handling | ✅ | ✅ | **TIE** |
| 9 | Cross-file flow | ⚠️ | ✅✅ | **Semantic** |
| 10 | Anonymous functions | ✅✅ | ❌ | **LSP** |
| 11 | Type definitions | ✅✅ | ⚠️ | **LSP** |
| 12 | Focus filtering (test/prod) | ✅ | ❌ (BUG) | **LSP** |
| 13 | Vague intent | ❌ | ✅✅ | **Semantic** |
| 14 | Multi-keyword technical | ✅ | ✅✅ | **Semantic** |
| 15 | Bug hunting | ✅ | ✅ | **TIE** |

### Final Tally

| Winner | Count |
|--------|-------|
| **LSP** | 6 |
| **Semantic** | 7 |
| **TIE** | 2 |

---

## Decision Matrix: When to Use What

### Use LSP When:
| Scenario | Serena Tool |
|----------|-------------|
| Know exact symbol name | `serena_find_symbol(name)` |
| Find all callers/references | `serena_find_referencing_symbols` |
| Pattern match symbols (`get*`, `*Handler`) | `serena_find_symbol(substring_matching=true)` |
| Type/interface definitions | `serena_find_symbol(include_kinds=[5,11])` |
| Anonymous function discovery | `serena_find_symbol("callback")` |
| Isolate test vs production | `serena_find_symbol(relative_path="src/")` |
| Get symbol body/implementation | `serena_find_symbol(include_body=true)` |
| Type safety verification | `lsp_diagnostics(severity="error")` |

### Use Semantic When:
| Scenario | Semanthicc Query |
|----------|------------------|
| Don't know symbol name, describe intent | `"how does X work"` |
| Search comments/TODOs/annotations | `"comment about migration"` |
| Find SQL/GraphQL/regex in strings | `"SQL query users table"` |
| Search config files (JSON/YAML) | `"tsconfig compiler options"` |
| Understand workflows and flows | `"indexing pipeline end to end"` |
| Vague improvement goals | `"make search faster"` |
| Multi-concept technical queries | `"lancedb vector hybrid search"` |
| Documentation + code together | Any query with `focus:mixed` |

### Use BOTH When:
| Scenario | Approach |
|----------|----------|
| Error handling review | LSP for error classes, Semantic for patterns |
| Bug hunting | LSP diagnostics + Semantic for edge cases |
| Refactoring safely | LSP for references, Semantic for context |
| Understanding new codebase | Semantic for concepts, LSP for precision |

---
LSP Dominates When:
- You know exact symbol names → 100% precision
- Finding references/callers → graph traversal only LSP can do
- Type definitions → kind filtering distinguishes definition vs usage
- Anonymous functions → LSP generates synthetic names
Semantic Dominates When:
- Conceptual queries ("how does X work")
- Comments, TODOs, annotations (invisible to LSP)
- DSLs in strings (SQL, GraphQL, regex)
- Config files (JSON, YAML)
- Multi-concept technical queries
- Vague intent ("make search faster")



## Bugs Discovered During Testing

### BUG: `focus:code` vs `focus:tests` produces identical results
**Severity**: Medium
**Location**: `src/search/search.ts` or `src/lance/embeddings.ts`
**Expected**: `focus:code` should boost `.ts` files, demote `.test.ts`
**Actual**: No difference in ranking

### BUG: Docs ranked #1 with `focus:code`
**Severity**: Medium
**Tests**: Test 2, 5, 7
**Expected**: Code files ranked higher than markdown
**Actual**: Markdown often ranks #1-2 even with code focus

---

## Conclusions

1. **LSP and Semantic are complementary, not competitors**
   - LSP: Precise, fast, complete for known symbols
   - Semantic: Flexible, conceptual, works on non-code

2. **Tool selection heuristic:**
   - Know the NAME → LSP
   - Know the PURPOSE → Semantic
   - Know BOTH → Start with LSP, fall back to Semantic

3. **Semantic search value proposition:**
   - Bridges intent to implementation (user says "validation", finds `validateEmbeddingConfig`)
   - Searches content invisible to LSP (comments, strings, configs)
   - Surfaces related docs and tests automatically

4. **Areas for Semantic improvement:**
   - Fix focus filtering (code vs tests vs docs)
   - Improve code ranking vs docs ranking
   - Consider function-level chunks instead of line-based

---

