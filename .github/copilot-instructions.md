# RCA Agent - Hobby Project Improvement Roadmap

**Version:** 3.1 (Updated with MVP Test Results)  
**Created:** December 25, 2025  
**Updated:** December 26, 2025 (MVP Test Completed)  
**Type:** Personal Hobby Project (zero monetization, zero privacy drama!)  
**Goal:** Build an awesome AI debugging assistant for learning and fun  
**Philosophy:** Experiment freely, learn constantly, ship when ready (not when deadline says)

**👥 Team Roles:**
- **Kai (Backend Developer):** ALL implementation (parsers, agents, tools, database, APIs, algorithms)
- **Sokchea (Frontend Developer):** UI + wiring ONLY (panels, buttons, VS Code extension API, calling Kai's functions)

---

## 🎉 MVP Test Results (December 26, 2025)

**Status:** ✅ TEST COMPLETED - Real-world validation on actual Android project!

### Quick Summary
```
Project: MVP Android App (Lab3) - Real Jetpack Compose project
Error: Invalid AGP version 8.10.0 in gradle/libs.versions.toml
Result: 40% usable (100% diagnosis, 17% solution quality)

✅ What Worked:
- Diagnosis: 100% accurate (correctly identified problem)
- Performance: 10.35s (88% faster than target!)
- Confidence: 80% (reliable)

❌ What Needs Work:
- Solution specificity: 17% (too generic)
- File identification: 30% (said "build.gradle" not exact file)
- Version suggestions: 0% (didn't know valid versions exist)
- Code examples: 0% (no before/after snippets)
```

**Key Insight:** The agent is EXCELLENT at diagnosis but POOR at providing actionable solutions. This roadmap now focuses on fixing that gap.

**Full Report:** `docs/REAL-PROJECT-TEST/`

---

## 🎯 Vision Statement

**Current State:** Functional RCA agent with 99% passing tests, 40% real-world usability (100% diagnosis, 17% solution)  
**Target State:** High success rate Kotlin error fixing agent (85-90%+ success) that provides specific, actionable fixes

**Scope Focus:**
- **Phase 3-4 (Now):** Master Kotlin/Android errors (Kotlin NPE, lateinit, Compose, coroutines)
- **Phase 5+ (Later):** Expand to other languages (TypeScript, Python, Rust, Go)
- **Role Division:** 
  - **Kai (Backend):** All implementation (parsers, agents, tools, database, APIs)
  - **Sokchea (Frontend):** UI + wiring (panels, buttons, extension API, calling Kai's functions)

**Hobby Project Philosophy:**
1. **Learning First** - Every feature is a learning opportunity (mess up? That's a lesson!)
2. **Accuracy Over Speed** - Better to be slow and correct than fast and wrong
3. **Practical Value** - Focus on fixing Kotlin errors with high success rate
4. **No Monetization Ever** - Free, open-source, built for the pure joy of building cool stuff
5. **Experimentation Welcome** - Try crazy ideas, break things, iterate quickly, have fun!
6. **Privacy? Not an Issue** - Everything runs locally, your code never leaves your machine
7. **Ship When Proud** - No artificial deadlines, release when you're excited to show it off

---

## 📊 Current Baseline (December 26, 2025)

### What's Working ✅
- Parser accuracy: 100% (26+ error types)
- Test coverage: 99% (878/878 tests passing)
- **Diagnosis accuracy: 100%** (MVP test - correctly identified AGP 8.10.0 issue)
- **Performance: 10.35s** (88% faster than 90s target! 🎉)
- Infrastructure: ChromaDB, caching, monitoring all functional
- Documentation: 9,650+ lines (maybe too much?)

### What Needs Work ❌
- **Real-world usability: 40%** ← THE BIG PROBLEM (confirmed by MVP test)
  - Diagnosis: 100% ✅ (tells you WHAT is wrong)
  - Solution specificity: 17% ❌ (doesn't tell you HOW to fix)
  - File identification: 30% ⚠️ (vague about exact files)
- Generic explanations ("update build.gradle" - which one?)
- Missing version-specific knowledge (doesn't suggest valid versions)
- No code examples (no before/after diffs)
- Vague fix suggestions ("ensure Maven Central configured" - how?)

### Root Cause of Low Usability
**After MVP test analysis, the main issues are:**
1. **No version lookup** - Doesn't know AGP 8.7.3 exists, can't suggest it
2. **Generic file references** - Says "build.gradle" not "gradle/libs.versions.toml"
3. **Missing code snippets** - No before/after examples
4. **Prompts lack specificity instructions** - LLM not told to be specific
5. **No domain knowledge base** - Can't validate versions or compatibility
6. **Single-pass reasoning** - Doesn't verify suggestions are correct

---

## 🗺️ Roadmap Overview (Streamlined for Real-World Impact)

**New Philosophy:** Focus on HIGH-IMPACT improvements that make the agent actually useful in complex projects. Skip experimental features until core usability is solid.

### Phase 2: VS Code Extension Enhancement 🔄
**Duration:** 3-4 weeks (streamlined from 5-chunk plan)  
**Status:** With Sokchea (Frontend Developer)  
**Goal:** Panel-based UI with essential features only

**What Changed:** Cut scope to ONLY essentials:
- ✅ Keep: Panel UI, error queue, batch processing, history
- ❌ Remove for now: Chat interface, visual debugging, educational modes
- **Why:** These are nice-to-have, not core usability

### Phase 3: Solution Quality Enhancement (HIGHEST PRIORITY) 🔴
**Duration:** 2-3 weeks  
**Goal:** Get from 40% → 80% usability by fixing solution specificity

**Focus Areas (Based on MVP Test):**
1. **Week 1:** Version knowledge base (0% → 90%)
   - AGP version database (8.0.0 - 9.0.0+)
   - Kotlin version database (1.5.0 - 2.0.0+)
   - Compatibility matrix
   
2. **Week 2:** Prompt engineering (17% → 70%)
   - Add "MUST specify exact file path with line number"
   - Add "MUST provide code snippet showing change"
   - Add few-shot examples (5 per error type)
   
3. **Week 3:** Fix generation (0% → 60%)
   - Generate code diffs (before/after)
   - File path resolution (detect exact file)
   - Validation logic (check if fix makes sense)

**Success Metric:** Usability 40% → 80%+

### Phase 4: Real-World Testing & Iteration 🎯
**Duration:** 2 weeks  
**Goal:** Test on 20+ complex Android projects, fix edge cases

**What to Test:**
- Multi-module projects (5+ modules)
- Legacy codebases (pre-2020)
- Jetpack Compose errors
- Gradle version conflicts
- Manifest permission issues

**Deliverable:** 80%+ usability on diverse project types

---

## 🚀 72-Hour Development Chunks (10 Chunks = ~30 Days)

### 📦 Chunk 1: Version Database Foundation (Days 1-3)
**Priority:** 🔴 CRITICAL  
**Goal:** Build AGP + Kotlin version databases  
**Duration:** 72 hours

**Tasks:**
- Hour 0-24: Scrape Maven Central for AGP versions (7.x - 9.x)
  - Create JSON schema
  - Write scraper script
  - Validate 150+ versions
- Hour 24-48: Build Kotlin version database
  - Scrape Kotlin releases (1.5.0 - 2.0.0+)
  - Add JDK compatibility data
  - Add AGP compatibility matrix
- Hour 48-72: Create compatibility matrix
  - AGP ↔ Kotlin version mapping
  - Gradle ↔ AGP compatibility
  - Test data integrity

**Deliverables:**
- [ ] `src/knowledge/agp-versions.json` (150+ versions)
- [ ] `src/knowledge/kotlin-versions.json` (50+ versions)
- [ ] `src/knowledge/compatibility-matrix.json`
- [ ] Unit tests for version data

**Success Metric:** Database completeness 95%+

---

### 📦 Chunk 2: Version Lookup Tool (Days 4-6)
**Priority:** 🔴 CRITICAL  
**Goal:** Enable agent to query version databases  
**Duration:** 72 hours

**Tasks:**
- Hour 0-24: Build VersionLookupTool.ts
  - Query AGP versions by range
  - Query Kotlin versions
  - Find latest stable/compatible versions
- Hour 24-48: Integration with agent workflow
  - Add tool to ToolRegistry
  - Test agent can use tool
  - Verify prompts trigger tool usage
- Hour 48-72: Validation + edge cases
  - Handle non-existent versions
  - Suggest alternatives
  - Test on MVP error case

**Deliverables:**
- [ ] `src/tools/VersionLookupTool.ts`
- [ ] Integration tests (20+ cases)
- [ ] Agent workflow integration
- [ ] Re-test MVP case (expect version suggestion)

**Success Metric:** Agent suggests valid versions 90%+ of time

---

### 📦 Chunk 3: Prompt Engineering - Specificity (Days 7-9)
**Priority:** 🔴 CRITICAL  
**Goal:** Fix vague solutions with better prompts  
**Duration:** 72 hours

**Tasks:**
- Hour 0-24: Add specificity instructions
  - "MUST specify exact file path"
  - "MUST include line numbers"
  - "MUST show code examples"
- Hour 24-48: Create structured response format
  - JSON schema for RCA responses
  - Enforce: problem, root cause, fix, code diff
  - Add validation logic
- Hour 48-72: Test on 10 error types
  - Gradle, Kotlin, Compose, XML, Manifest
  - Measure before/after specificity
  - Collect improvement metrics

**Deliverables:**
- [ ] Updated system prompts in `src/agent/PromptEngine.ts`
- [ ] Response validation schema
- [ ] Before/after comparison report
- [ ] Specificity metrics dashboard

**Success Metric:** Solution specificity 17% → 70%

---

### 📦 Chunk 4: Few-Shot Examples Library (Days 10-12)
**Priority:** 🔴 CRITICAL  
**Goal:** Teach agent with concrete examples  
**Duration:** 72 hours

**Tasks:**
- Hour 0-24: Create 15 Gradle error examples
  - AGP version conflicts
  - Dependency resolution failures
  - Plugin compatibility issues
- Hour 24-48: Create 15 Kotlin error examples
  - NPE (lateinit not initialized)
  - Type mismatches
  - Coroutine issues
- Hour 48-72: Create 10+ Compose/XML/Manifest examples
  - Compose API breakages
  - XML layout inflation
  - Manifest permission errors
- Integration: Add to PromptEngine

**Deliverables:**
- [ ] `src/knowledge/few-shot-examples.json` (40+ examples)
- [ ] Each example: error → diagnosis → specific fix → code diff
- [ ] PromptEngine integration
- [ ] A/B test: with/without examples

**Success Metric:** Fix quality improved on 80%+ of error types

---

### 📦 Chunk 5: Fix Generator Foundation (Days 13-15)
**Priority:** 🟡 HIGH  
**Goal:** Generate code diffs, not just text  
**Duration:** 72 hours

**Tasks:**
- Hour 0-24: Build FixGenerator.ts
  - Parse error location (file, line)
  - Read surrounding code context
  - Generate before/after diff
- Hour 24-48: Diff formatting utilities
  - Markdown code blocks with syntax highlighting
  - Unified diff format (- / +)
  - Multi-file diff support
- Hour 48-72: Integration + testing
  - Add to agent workflow
  - Test on 10 error types
  - Validate diff correctness

**Deliverables:**
- [ ] `src/agent/FixGenerator.ts`
- [ ] Diff formatting utilities
- [ ] Integration tests (15+ cases)
- [ ] VS Code diff preview support

**Success Metric:** Fix generation rate 0% → 60%

---

### 📦 Chunk 6: File Path Resolution (Days 16-18)
**Priority:** 🟡 HIGH  
**Goal:** Find exact files, not generic names  
**Duration:** 72 hours

**Tasks:**
- Hour 0-24: Build FileResolver.ts
  - Analyze project structure
  - Detect Gradle catalogs vs build.gradle
  - Map generic names to exact paths
- Hour 24-48: Pattern matching logic
  - "build.gradle" → detect which one (root, app, module)
  - "libs.versions.toml" → detect if catalog used
  - Handle multi-module projects
- Hour 48-72: Integration + edge cases
  - Test on 5 different project structures
  - Handle missing files gracefully
  - Suggest file creation if not exists

**Deliverables:**
- [ ] `src/utils/FileResolver.ts`
- [ ] Project structure analyzer
- [ ] Integration with FixGenerator
- [ ] Tests on diverse project types

**Success Metric:** File identification 30% → 85%

---

### 📦 Chunk 7: Real-World Test Suite Part 1 (Days 19-21)
**Priority:** 🔴 CRITICAL  
**Goal:** Test on 10+ diverse Android errors  
**Duration:** 72 hours

**Test Cases (5 for this chunk):**
1. AGP version conflict (already tested)
2. Kotlin lateinit NPE
3. Compose API breakage (1.5 → 1.6)
4. XML layout inflation error
5. Multi-module dependency conflict

**Tasks:**
- Hour 0-48: Create test projects + run RCA
  - Each error in isolated project
  - Document expected vs actual results
  - Measure all metrics (usability, specificity, etc.)
- Hour 48-72: Analyze failures + quick fixes
  - Identify top 3 failure patterns
  - Fix critical issues
  - Re-test

**Deliverables:**
- [ ] 5 test projects in `tests/real-world/`
- [ ] Test results with metrics
- [ ] Failure analysis report
- [ ] Critical bug fixes

**Success Metric:** 70%+ usability on 5 error types

---

### 📦 Chunk 8: Real-World Test Suite Part 2 (Days 22-24)
**Priority:** 🔴 CRITICAL  
**Goal:** Test remaining error types  
**Duration:** 72 hours

**Test Cases (5 more):**
6. Manifest permission missing
7. Gradle sync failed (network)
8. Build cache corruption
9. R8/ProGuard rule missing
10. Jetpack Navigation argument mismatch

**Tasks:**
- Hour 0-48: Create test projects + run RCA
  - Same process as Chunk 7
  - Collect comprehensive metrics
- Hour 48-72: Compare with Phase 3 baseline
  - Overall usability improvement
  - Identify remaining weak spots
  - Plan Phase 4 focus areas

**Deliverables:**
- [ ] 5 more test projects
- [ ] Complete 10-case test suite results
- [ ] Usability comparison report (40% → ?%)
- [ ] Phase 4 priority list

**Success Metric:** 80%+ average usability across all 10 cases

---

### 📦 Chunk 9: Bug Fixes & Iteration (Days 25-27)
**Priority:** 🔴 CRITICAL  
**Goal:** Fix remaining issues from testing  
**Duration:** 72 hours

**Tasks:**
- Hour 0-24: Fix top 5 bugs from test results
  - Prioritize by impact
  - Test fixes thoroughly
- Hour 24-48: Edge case handling
  - Multi-module projects
  - Legacy codebases (pre-2020)
  - Non-standard project structures
- Hour 48-72: Performance tuning
  - Optimize slow queries
  - Improve caching
  - Maintain <15s latency

**Deliverables:**
- [ ] 5+ bug fixes
- [ ] Edge case handling
- [ ] Performance optimizations
- [ ] Regression tests

**Success Metric:** No critical bugs, usability maintained

---

### 📦 Chunk 10: Final Validation & Documentation (Days 28-30)
**Priority:** 🟡 HIGH  
**Goal:** Polish, document, prepare for Phase 4  
**Duration:** 72 hours

**Tasks:**
- Hour 0-24: Final end-to-end testing
  - Re-run all 10 test cases
  - Verify improvements are stable
  - Document final metrics
- Hour 24-48: Update documentation
  - Update IMPROVEMENT_ROADMAP.md with results
  - Write Phase 3 completion summary
  - Create Phase 4 detailed plan
- Hour 48-72: Demo preparation
  - Create demo video
  - Write blog post about journey
  - Prepare GitHub README update

**Deliverables:**
- [ ] Final test results report
- [ ] Phase 3 completion document
- [ ] Updated documentation
- [ ] Demo materials
- [ ] Phase 4 kickoff plan

**Success Metric:** Overall usability 80%+ achieved and documented

---

## 📊 Chunk Progress Tracking (LLM/Vector DB Focused)

| Chunk | Focus | Duration | LLM/Vector DB Work | Status | Usability Impact |
|-------|-------|----------|---------------------|--------|------------------|
| 1 | Version DB + Embeddings | 72h | 🧠 ChromaDB collections, semantic search | ⏳ Not Started | +0% (foundation) |
| 2 | Version Tool + RAG | 72h | 🧠 RAG retrieval, prompt integration | ⏳ Not Started | +15% (suggestions) |
| 3 | LLM Prompt Engineering | 72h | 🧠 CoT, structured output, JSON mode | ⏳ Not Started | +25% (specificity) |
| 4 | Few-Shot RAG | 72h | 🧠 Dynamic example retrieval, embeddings | ⏳ Not Started | +10% (quality) |
| 5 | Fix Generator + LLM | 72h | 🧠 LLM-powered diff generation | ⏳ Not Started | +10% (code diffs) |
| 6 | File Resolver + Embeddings | 72h | 🧠 Semantic file search via vectors | ⏳ Not Started | +10% (accuracy) |
| 7 | Testing Part 1 | 72h | 🧠 LLM output quality metrics | ⏳ Not Started | Validation |
| 8 | Testing Part 2 | 72h | 🧠 Prompt variant A/B testing | ⏳ Not Started | Validation |
| 9 | LLM Fine-Tuning Prep | 72h | 🧠 Dataset curation, embedding optimization | ⏳ Not Started | +10% (polish) |
| 10 | Final Validation | 72h | 🧠 End-to-end RAG pipeline test | ⏳ Not Started | Documentation |

**Total Duration:** 30 days (720 hours)  
**Expected Improvement:** 40% → 80%+ usability  
**Target Completion:** Late January 2026

**🧠 LLM/Vector DB Focus Throughout:**
- **Chunks 1-2:** Foundation (ChromaDB setup, RAG architecture)
- **Chunks 3-4:** Advanced prompt engineering + few-shot learning
- **Chunks 5-6:** LLM-powered code generation + semantic search
- **Chunks 7-8:** LLM output quality testing + optimization
- **Chunks 9-10:** Fine-tuning preparation + RAG refinement

---

## 🚀 Immediate Next Steps (Week-by-Week Plan)

### Week 1: Version Knowledge Base (HIGHEST IMPACT) 🔴
**Goal:** Enable specific version suggestions (0% → 90%)

**Tasks:**
1. **Day 1-2:** Build AGP version database
   - Scrape Maven Central for all AGP versions (7.x - 9.x)
   - Store: version, release date, status (stable/alpha/beta), compatibility
   - Create JSON: `src/knowledge/agp-versions.json`

2. **Day 3-4:** Build Kotlin version database
   - Scrape Kotlin releases (1.5.0 - 2.0.0+)
   - Store: version, release date, JDK compatibility, AGP compatibility

3. **Day 5:** Version lookup tool
   - `VersionLookupTool.ts` - Query versions from database
   - Integrate into agent's tool registry
   - Test: Can agent suggest "8.7.3" instead of "update to latest"?

**Success Metric:** Agent can suggest valid versions 90%+ of the time

### Week 2: Prompt Engineering (QUICK WIN) ⚡
**Goal:** Fix vague solutions (17% → 70%)

**Tasks:**
1. **Day 1-2:** Add specificity instructions to prompts
   ```typescript
   System prompt changes:
   - "MUST specify exact file path (e.g., gradle/libs.versions.toml line 5)"
   - "MUST provide code snippet showing before/after"
   - "MUST suggest specific version numbers, not 'latest'"
   - "MUST validate version compatibility before suggesting"
   ```

2. **Day 3-4:** Add few-shot examples
   - 5 examples per error type (Gradle, Kotlin, Compose, XML, Manifest)
   - Each example shows: error → diagnosis → specific fix with code

3. **Day 5:** Test on MVP project
   - Re-run AGP error test
   - Measure improvement in solution specificity

**Success Metric:** Solution quality 17% → 70%

### Week 3: Fix Generation (CODE DIFFS) 📝
**Goal:** Generate actual code changes (0% → 60%)

**Tasks:**
1. **Day 1-3:** Build FixGenerator.ts
   - Parse file structure to find exact file
   - Generate before/after code diff
   - Format as markdown code block with syntax highlighting

2. **Day 4-5:** File path resolution
   - `FileResolver.ts` - Detect exact file from generic reference
   - Example: "build.gradle" → "gradle/libs.versions.toml" (if catalog used)

**Success Metric:** Agent shows code diffs 60%+ of the time

### Week 4: Testing & Validation 🧪
**Goal:** Test on 10+ diverse errors, reach 80% usability

**Test Matrix:**
```
Error Types to Test:
✅ Gradle dependency (AGP version) - already tested
⏳ Kotlin NPE (lateinit not initialized)
⏳ Compose API breakage (1.5.0 → 1.6.0)
⏳ XML layout inflation error
⏳ Manifest permission missing
⏳ Multi-module dependency conflict
⏳ Gradle sync failed (network issue)
⏳ Build cache corruption
⏳ R8/ProGuard rule missing
⏳ Jetpack Navigation argument mismatch
```

**Success Metric:** 80%+ usability across all error types

---

# 🔴 PHASE 3: Solution Quality Enhancement (4 WEEKS - FOCUSED)

**Duration:** 4 weeks  
**Focus:** Fix the 40% usability problem through targeted improvements  
**Goal:** 40% → 80%+ usability on real-world complex projects

**What Changed from Original Plan:**
- ❌ Removed: Multi-pass reasoning, semantic code search, historical patterns (nice-to-have)
- ✅ Kept: Version knowledge, prompt engineering, fix generation (MUST-have)
- **Why:** Focus on 20% of features that deliver 80% of value

---

## Week 1: Version Knowledge Base

### 3.1: Domain Knowledge Database (STREAMLINED)
**Priority:** 🔴 CRITICAL  
**Impact:** Eliminate version hallucinations (0% → 90%)

**Tasks:**
1. **AGP Version Database** (2 days)
   ```typescript
   // src/knowledge/agp-versions.json
   {
     "versions": [
       {
         "version": "8.7.3",
         "releaseDate": "2024-11-15",
         "status": "stable",
         "minKotlin": "1.9.0",
         "minJdk": "17",
         "breaking_changes": []
       },
       // ... 150+ versions from Maven Central
     ]
   }
   
   // src/tools/VersionLookupTool.ts
   class VersionLookupTool {
     async findValidVersions(requested: string): Promise<Version[]> {
       // Query JSON database
       // Return nearest stable versions
     }
     
     async checkCompatibility(agp: string, kotlin: string): Promise<boolean> {
       // Check compatibility matrix
     }
   }
   ```

2. **Kotlin Version Database** (1 day)
   ```typescript
   // src/knowledge/kotlin-versions.json
   {
     "versions": [
       {
         "version": "2.0.0",
         "releaseDate": "2024-05-21",
         "jvmTarget": ["17", "21"],
         "compatibleAgp": ["8.3.0+"]
       }
     ]
   }
   ```

3. **Integration into Agent** (1 day)
   ```typescript
   // Add to tool registry
   toolRegistry.register(new VersionLookupTool());
   
   // Update prompts to use it
   "When encountering version errors, ALWAYS use VersionLookupTool 
    to find valid versions before suggesting fixes"
   ```

**Success Metrics:**
- Version suggestions: 0% → 90%
- Version accuracy: 95%+ (suggests actual valid versions)
- Agent uses tool: 100% of version-related errors

**Deliverables:**
- [ ] agp-versions.json (150+ versions)
- [ ] kotlin-versions.json (50+ versions)
- [ ] VersionLookupTool.ts
- [ ] Integration tests (20+ cases)

---

## Week 2: Prompt Engineering Overhaul

### 3.2: Context-Aware System Prompts (SIMPLIFIED)
**Priority:** 🔴 CRITICAL  
**Impact:** Better specificity (17% → 70%)

**Tasks:**
1. **Add Specificity Instructions** (2 days)
   ```typescript
   // src/agent/prompts/system-prompt.ts
   const SPECIFICITY_RULES = `
   CRITICAL RULES FOR SOLUTIONS:
   
   1. File Paths: MUST be exact with line numbers
      ❌ Bad: "Update build.gradle"
      ✅ Good: "Update gradle/libs.versions.toml line 5"
   
   2. Version Numbers: MUST be specific and validated
      ❌ Bad: "Update to latest AGP"
      ✅ Good: "Update to AGP 8.7.3 (stable, released Nov 2024)"
      
   3. Code Examples: MUST show before/after
      ❌ Bad: "Change the version"
      ✅ Good:
      Before: agp = "8.10.0"
      After:  agp = "8.7.3"
   
   4. Verification Steps: MUST explain how to test fix
      ❌ Bad: "This should fix it"
      ✅ Good: "Run './gradlew build' to verify fix works"
   `;
   ```

2. **Few-Shot Examples by Error Type** (2 days)
   ```typescript
   // For Gradle errors:
   const GRADLE_FEW_SHOT = `
   Example 1:
   Error: "Could not find com.android.tools.build:gradle:8.10.0"
   
   Diagnosis:
   - Error type: Gradle dependency not found
   - Root cause: AGP 8.10.0 doesn't exist in Maven Central
   - File: gradle/libs.versions.toml, line 5
   
   Solution:
   1. Check valid versions using VersionLookupTool
   2. Latest stable: 8.7.3 (Nov 2024)
   3. Update gradle/libs.versions.toml line 5:
      
      Before:
      agp = "8.10.0"
      
      After:
      agp = "8.7.3"
   
   4. Verify: Run './gradlew --version' to confirm AGP updated
   `;
   
   // Add 5 examples each for: Gradle, Kotlin, Compose, XML, Manifest
   ```

**Success Metrics:**
- Solution specificity: 17% → 70%
- File identification: 30% → 90%
- Code examples: 0% → 80%

**Deliverables:**
- [ ] Updated system prompts with specificity rules
- [ ] 25+ few-shot examples (5 per category)
- [ ] Before/after comparison on MVP test

---

## Week 3: Fix Generation & File Resolution

### 3.3: Code Diff Generation (NEW FEATURE)
**Priority:** 🟡 HIGH  
**Impact:** Visual code fixes (0% → 60%)

**Tasks:**
1. **FixGenerator Module** (3 days)
   ```typescript
   // src/agent/FixGenerator.ts
   class FixGenerator {
     async generateFix(error: ParsedError, rootCause: string): Promise<Fix> {
       // 1. Identify exact file and line
       const file = await this.resolveFile(error.filePath);
       
       // 2. Read current content
       const content = await fs.readFile(file, 'utf-8');
       
       // 3. Generate proposed change
       const fix = await this.llm.generateFix({
         error,
         rootCause,
         currentContent: content,
         context: await this.getContext(file)
       });
       
       // 4. Create diff
       const diff = this.createDiff(content, fix.newContent);
       
       return {
         file: file.path,
         line: fix.line,
         before: fix.oldCode,
         after: fix.newCode,
         diff: diff,
         explanation: fix.reasoning
       };
     }
   }
   ```

2. **File Resolution Logic** (2 days)
   ```typescript
   // src/utils/FileResolver.ts
   class FileResolver {
     async resolveFile(genericPath: string, projectRoot: string): Promise<string> {
       // Handle common cases:
       // "build.gradle" → could be:
       //   - build.gradle (root)
       //   - app/build.gradle (module)
       //   - gradle/libs.versions.toml (catalog)
       
       // Strategy:
       // 1. Check if version catalog exists
       // 2. Parse build.gradle for dependencies
       // 3. Determine which file actually contains the error
       
       const candidates = await this.findCandidates(genericPath);
       return this.selectMostLikely(candidates, error);
     }
   }
   ```

**Success Metrics:**
- Fix generation rate: 0% → 60%
- File resolution accuracy: 30% → 85%
- Diff format quality: Readable and actionable

**Deliverables:**
- [ ] FixGenerator.ts
- [ ] FileResolver.ts
- [ ] Diff formatting utilities
- [ ] Integration with agent workflow

---

## Week 4: Testing & Iteration

### 3.4: Real-World Validation (ESSENTIAL)
**Priority:** 🔴 CRITICAL  
**Goal:** Test on 10 diverse error types, measure improvement

**Test Suite:**
```typescript
// tests/real-world/
const TEST_CASES = [
  {
    name: "Gradle AGP version error",
    project: "MVP_Android_Lab3",
    error: "Could not find AGP 8.10.0",
    expectedFix: "Update gradle/libs.versions.toml line 5 to 8.7.3",
    baseline: { usability: 40% },
    target: { usability: 80% }
  },
  {
    name: "Kotlin lateinit NPE",
    project: "Real_Kotlin_Project",
    error: "lateinit property not initialized",
    expectedFix: "Initialize viewModel in onCreate() before use",
    baseline: { usability: "unknown" },
    target: { usability: 75% }
  },
  // ... 8 more test cases
];
```

**Tasks:**
1. **Day 1-2:** Run all 10 test cases
   - Collect baseline metrics
   - Identify failure patterns

2. **Day 3-4:** Fix top 3 failure modes
   - Adjust prompts based on failures
   - Update knowledge base with missing info
   - Re-test

3. **Day 5:** Final validation
   - Overall usability: Target 80%+
   - Document remaining gaps
   - Plan Phase 4 improvements

**Success Metrics:**
- Overall usability: 40% → 80%+
- Test coverage: 10+ diverse error types
- No regressions: Existing cases still work

**Deliverables:**
- [ ] 10-case test suite with results
- [ ] Performance comparison report
- [ ] Documented failure cases for Phase 4
- [ ] Usability scores by error type
- [ ] 100+ labeled errors dataset
- [ ] Annotation guidelines
- [ ] Dataset split (train 70%, val 15%, test 15%)
- [ ] Synthetic data generator

**Success Criteria:**
- Identified top 3 failure patterns
- Built tools to debug agent reasoning
- Created evaluation dataset
- Ready to start targeted improvements

---

# 🔴 PHASE 3: Intelligence Enhancement (HIGH PRIORITY)
**Duration:** 4-8 weeks  
**Focus:** Getting accuracy from 50% → 80%+

**Why These Features:**
Based on Phase 2.5 analysis, these are the highest-impact improvements for accuracy.

---

## Week 1-2: Prompt Engineering Overhaul

### Objective
Stop LLM from giving generic/wrong answers by adding more context

### 3.1: Context-Aware System Prompts
**Priority:** 🔴 CRITICAL (HIGHEST IMPACT)  
**Impact:** +50% usability improvement expected (40% → 90%)
**Why:** MVP test shows diagnosis is perfect, but solutions are too vague

**Tasks:**
1. **Version-Specific Knowledge Injection**
   ```typescript
   // src/agent/VersionContextBuilder.ts
   class VersionContextBuilder {
     // Add to system prompt based on detected versions
     getAGPContext(version: string): string {
       // AGP 8.10.0 -> "Version doesn't exist. Valid: 8.7.x, 8.9.x, 9.0.x"
       // AGP 7.x -> "Deprecated, consider upgrading to 8.7.3+"
       // AGP 9.0.x -> "Latest stable"
     }
     
     getKotlinContext(version: string): string {
       // Kotlin 2.0.x -> "New K2 compiler, breaking changes from 1.9"
       // Kotlin 1.9.x -> "Stable, consider upgrading to 2.0+"
     }
     
     getComposeContext(version: string): string {
       // Compose 1.6.x -> "Material3 recommended"
       // Compose 1.5.x -> "Update for performance improvements"
     }
   }
   ```

2. **Error-Type Specific Prompts**
   ```typescript
   // src/agent/PromptTemplates.ts
   const GRADLE_DEPENDENCY_TEMPLATE = `
   You are analyzing a Gradle dependency resolution error.
   
   CRITICAL INSTRUCTIONS:
   1. If error mentions specific version (e.g., 8.10.0), validate it EXISTS
   2. For AGP versions, check against known valid ranges:
      - 7.x series: 7.0.0 - 7.4.2
      - 8.x series: 8.0.0 - 8.7.3 (NO 8.8.x or 8.10.x)
      - 9.x series: 9.0.0+
   3. Suggest 2-3 specific valid versions with reasoning
   4. Include migration steps if major version change needed
   
   AVOID:
   - Generic "update your dependencies"
   - Unrelated configuration changes
   - Vague "ensure X is configured correctly"
   
   PROVIDE:
   - Exact version numbers to use
   - Which file to edit (with line numbers)
   - Why the current version fails
   - Compatibility considerations
   `;
   ```

3. **Few-Shot Learning Enhancement**
   ```typescript
   // src/agent/FewShotExamples.ts
   const AGP_VERSION_EXAMPLES = [
     {
       error: "Could not find com.android.tools.build:gradle:8.10.0",
       goodAnalysis: `
       ROOT CAUSE: AGP version 8.10.0 does not exist. The 8.x series skips 
       8.8.x and 8.10.x versions. Valid options are:
       - 8.7.3 (stable, recommended)
       - 8.9.0-alpha01 (preview)
       - 9.0.0 (latest stable)
       
       FIX: Update gradle/libs.versions.toml line 2:
       agp = "8.7.3"  # or "9.0.0" for latest features
       `,
       badAnalysis: `The build configuration is incorrect. Ensure gradle is properly set up.`
     },
     // Add 20+ real-world examples for each error type
   ];
   ```

**Success Metrics (Based on MVP Test):**
- Overall Usability: 40% → 90% (+50%)
- File Identification: 30% → 95% (+65%)
- Version Suggestions: 0% → 90% (+90%)
- Code Examples: 0% → 85% (+85%)
- Diagnosis Accuracy: 100% → 100% (already perfect!)

**Deliverables:**
- [ ] VersionContextBuilder.ts
- [ ] 30+ error-type specific prompt templates
- [ ] 100+ few-shot examples (5 per error type)
- [ ] Prompt testing framework
- [ ] A/B testing infrastructure

---

### 3.2: Domain Knowledge Database
**Priority:** 🔴 CRITICAL (2ND HIGHEST IMPACT)  
**Impact:** Eliminate version hallucinations (MVP test: agent didn't know valid AGP versions)
**Why:** LLM can't suggest versions it doesn't know exist

**Tasks:**
1. **AGP Version Database**
   ```typescript
   // src/knowledge/AGPVersionDatabase.ts
   interface AGPVersion {
     version: string;
     releaseDate: Date;
     status: 'stable' | 'beta' | 'alpha' | 'deprecated';
     kotlinCompatibility: string[];
     gradleCompatibility: string[];
     knownIssues: string[];
     migrationGuide?: string;
   }
   
   const AGP_VERSIONS: AGPVersion[] = [
     {
       version: '9.0.0',
       releaseDate: new Date('2024-10-15'),
       status: 'stable',
       kotlinCompatibility: ['2.0.0+'],
       gradleCompatibility: ['8.9+'],
       knownIssues: [],
       migrationGuide: 'https://developer.android.com/build/releases/gradle-plugin#9-0-0'
     },
     // ... all versions from 7.0.0 to latest
   ];
   
   class AGPVersionValidator {
     exists(version: string): boolean;
     getLatestStable(): string;
     getSuggestedVersions(current: string): string[];
     getMigrationPath(from: string, to: string): MigrationStep[];
   }
   ```

2. **Jetpack Compose API Database**
   ```typescript
   // src/knowledge/ComposeAPIDatabase.ts
   interface ComposeAPI {
     name: string;
     introducedIn: string;
     deprecatedIn?: string;
     replacedBy?: string;
     commonMistakes: string[];
     bestPractices: string[];
     examples: CodeExample[];
   }
   
   const COMPOSE_APIS = {
     remember: {
       commonMistakes: [
         'Using remember without keys for state that depends on external values',
         'Over-remembering immutable values',
       ],
       bestPractices: [
         'Use remember(key1, key2) when state depends on specific values',
         'Use rememberSaveable for state that survives config changes',
       ]
     },
     // ... 50+ Compose APIs
   };
   ```

3. **Gradle Plugin Compatibility Matrix**
   ```typescript
   // src/knowledge/CompatibilityMatrix.ts
   class CompatibilityChecker {
     isCompatible(
       agp: string,
       kotlin: string,
       gradle: string,
       compose?: string
     ): CompatibilityResult;
     
     getSuggestedCombination(constraints: {
       agp?: string;
       kotlin?: string;
       gradle?: string;
     }): VersionCombination;
   }
   ```

**Success Metrics:**
- Version validation: 100% accuracy
- Suggestion relevance: 90%+
- Compatibility detection: 95%+

**Deliverables:**
- [ ] AGP version database (150+ versions)
- [ ] Kotlin version database (100+ versions)
- [ ] Compose API database (50+ APIs)
- [ ] Gradle compatibility matrix
- [ ] Automated update pipeline (weekly scraping)

---

### 3.3: Multi-Pass Reasoning
**Priority:** 🟡 HIGH  
**Impact:** Better root cause identification through deeper analysis

**Tasks:**
1. **Hypothesis Generation & Validation**
   ```typescript
   // src/agent/MultiPassAgent.ts
   class MultiPassAgent extends MinimalReactAgent {
     async analyze(error: ParsedError): Promise<RCAResult> {
       // Pass 1: Generate 3 hypotheses
       const hypotheses = await this.generateHypotheses(error);
       
       // Pass 2: Validate each hypothesis with tools
       const validatedHypotheses = await Promise.all(
         hypotheses.map(h => this.validateHypothesis(h, error))
       );
       
       // Pass 3: Rank by evidence and select best
       const ranked = this.rankHypotheses(validatedHypotheses);
       
       // Pass 4: Generate detailed explanation for top hypothesis
       const rootCause = await this.explainRootCause(ranked[0], error);
       
       return rootCause;
     }
     
     private async generateHypotheses(error: ParsedError): Promise<Hypothesis[]> {
       // Use LLM to brainstorm 3 possible root causes
       // Example: AGP version error could be:
       // 1. Invalid version number
       // 2. Network/repository issue
       // 3. Cache corruption
     }
     
     private async validateHypothesis(
       hypothesis: Hypothesis,
       error: ParsedError
     ): Promise<ValidatedHypothesis> {
       // Use tools to gather evidence
       // - Check version databases
       // - Read relevant files
       // - Search documentation
       // - Query ChromaDB for similar cases
     }
   }
   ```

2. **Evidence-Based Confidence Scoring**
   ```typescript
   // src/agent/EvidenceScorer.ts
   class EvidenceScorer {
     calculateConfidence(hypothesis: ValidatedHypothesis): number {
       let confidence = 0.5; // Base 50%
       
       // +20% if version found in database
       if (hypothesis.evidence.versionValidated) confidence += 0.2;
       
       // +15% if similar case in ChromaDB
       if (hypothesis.evidence.similarCases > 3) confidence += 0.15;
       
       // +10% if documentation confirms
       if (hypothesis.evidence.docsConfirm) confidence += 0.1;
       
       // -20% if contradictory evidence
       if (hypothesis.evidence.contradictions > 0) confidence -= 0.2;
       
       return Math.max(0, Math.min(1, confidence));
     }
   }
   ```

**Success Metrics:**
- Confidence accuracy: 85%+ (confidence matches actual correctness)
- False positive rate: <5%
- Analysis depth: 3+ hypotheses considered

**Deliverables:**
- [ ] MultiPassAgent.ts
- [ ] Hypothesis validation framework
- [ ] Evidence-based confidence scoring
- [ ] Contradiction detection logic

---

## Week 3-4: Advanced Tool Development

### 3.4: Intelligent Code Analysis Tools
**Priority:** 🟡 HIGH  
**Impact:** Better context understanding and fix generation

**Tasks:**
1. **Semantic Code Search Tool**
   ```typescript
   // src/tools/SemanticCodeSearchTool.ts
   class SemanticCodeSearchTool extends Tool {
     // Find code patterns related to error
     async findRelatedCode(error: ParsedError): Promise<CodeLocation[]> {
       // Example: For AGP version error, find all version declarations
       const query = this.buildSemanticQuery(error);
       const results = await this.semanticSearch(query);
       return results.filter(r => r.relevance > 0.7);
     }
     
     private buildSemanticQuery(error: ParsedError): string {
       // AGP error -> "gradle plugin version declaration"
       // Kotlin NPE -> "variable initialization lateinit"
       // Compose recomposition -> "state management remember"
     }
   }
   ```

2. **Dependency Graph Analyzer**
   ```typescript
   // src/tools/DependencyGraphTool.ts
   class DependencyGraphTool extends Tool {
     // Analyze entire dependency tree for conflicts
     async analyzeDependencies(projectPath: string): Promise<DependencyGraph> {
       // Parse all build.gradle files
       // Build dependency tree
       // Detect conflicts, transitive issues
       // Find version mismatches
     }
     
     async findConflictingDependencies(
       dependency: string
     ): Promise<Conflict[]> {
       // Example: androidx.compose:* versions must match
       // Example: AGP and Kotlin must be compatible
     }
   }
   ```

3. **Historical Error Pattern Tool**
   ```typescript
   // src/tools/HistoricalPatternTool.ts
   class HistoricalPatternTool extends Tool {
     // Search ChromaDB for similar errors in project history
     async findSimilarErrorsInProject(
       error: ParsedError,
       projectPath: string
     ): Promise<HistoricalError[]> {
       // Find errors in same file
       // Find errors in same module
       // Find errors with same type
       // Return successful fixes
     }
     
     async getSuccessfulFixes(errorHash: string): Promise<Fix[]> {
       // Query feedback database for positive fixes
       // Return code changes that worked
     }
   }
   ```

4. **Documentation Search Tool (Enhanced)**
   ```typescript
   // src/tools/EnhancedDocsSearchTool.ts
   class EnhancedDocsSearchTool extends AndroidDocsSearchTool {
     // Expanded to include:
     // - Kotlin docs
     // - Gradle docs
     // - Jetpack Compose docs
     // - Stack Overflow (cached)
     // - GitHub issues (cached)
     
     async searchMultipleSources(query: string): Promise<DocResult[]> {
       const results = await Promise.all([
         this.searchAndroidDocs(query),
         this.searchKotlinDocs(query),
         this.searchGradleDocs(query),
         this.searchStackOverflow(query),
         this.searchGitHubIssues(query),
       ]);
       
       return this.rankAndMerge(results.flat());
     }
   }
   ```

**Success Metrics:**
- Tool usage: 80%+ of analyses use 3+ tools
- Tool accuracy: 90%+ relevant results
- Context quality: 85%+ of fixes include proper context

**Deliverables:**
- [ ] SemanticCodeSearchTool.ts
- [ ] DependencyGraphTool.ts
- [ ] HistoricalPatternTool.ts
- [ ] EnhancedDocsSearchTool.ts (with Kotlin, Gradle, SO)
- [ ] Tool orchestration logic

---

### 3.5: Fix Generation & Validation
**Priority:** 🟡 HIGH  
**Impact:** Generate code fixes, not just explanations

**Tasks:**
1. **Code Diff Generation**
   ```typescript
   // src/agent/FixGenerator.ts
   class FixGenerator {
     async generateFix(
       error: ParsedError,
       rootCause: string,
       context: CodeContext
     ): Promise<CodeFix[]> {
       // Generate multiple fix options
       const fixes = await this.llm.generateFixes(error, rootCause, context);
       
       // Validate each fix
       const validated = await Promise.all(
         fixes.map(f => this.validateFix(f, context))
       );
       
       // Rank by safety and effectiveness
       return this.rankFixes(validated);
     }
     
     private async validateFix(
       fix: CodeFix,
       context: CodeContext
     ): Promise<ValidatedFix> {
       // Syntax check
       const syntaxValid = await this.checkSyntax(fix.code);
       
       // Type check (if LSP available)
       const typeValid = await this.checkTypes(fix.code);
       
       // Semantic check (doesn't break other code)
       const semanticValid = await this.checkSemantics(fix, context);
       
       return { ...fix, syntaxValid, typeValid, semanticValid };
     }
   }
   ```

2. **One-Click Fix Application**
   ```typescript
   // vscode-extension/src/commands/applyFix.ts
   export async function applyFix(fix: CodeFix) {
     // Show diff preview
     const userApproved = await showDiffPreview(fix);
     
     if (userApproved) {
       // Apply fix with undo support
       await applyCodeEdit(fix);
       
       // Track fix application
       await trackFixApplication(fix.id, 'applied');
       
       // Suggest next steps
       await showNextSteps(fix);
     }
   }
   ```

3. **Fix Testing (Optional)**
   ```typescript
   // src/agent/FixTester.ts
   class FixTester {
     // If user has tests, run them after fix
     async testFix(fix: CodeFix, projectPath: string): Promise<TestResult> {
       // Apply fix to temp copy
       // Run existing tests
       // Return results
     }
   }
   ```

**Success Metrics:**
- Fix generation rate: 80%+ of errors get suggested fixes
- Fix correctness: 70%+ of applied fixes resolve issue
- User acceptance: 60%+ of fixes accepted and applied

**Deliverables:**
- [ ] FixGenerator.ts
- [ ] Fix validation logic
- [ ] VS Code one-click fix integration
- [ ] Diff preview UI component
- [ ] Fix testing framework (optional)

---

## Week 5-6: Performance & Testing

### 3.6: Latency Optimization (OPTIONAL)
**Priority:** 🟢 LOW (MVP test: already excellent at 10.35s!)  
**Goal:** Maintain current 10.35s performance (already 88% faster than target)
**Note:** Performance is NOT a problem. Focus on solution quality instead.

**Success Metrics (Already Exceeded!):**
- ✅ Median latency: 10.35s (already 88% faster than 90s target!)
- ✅ P90 latency: <20s (achieved)
- Cache hit rate: 60% → 80% (nice to have)
- First response (streaming): <3s (nice to have)

**Verdict:** Performance is NOT a bottleneck. Skip this unless bored.

**Tasks:**
1. **Parallel Tool Execution (OPTIONAL)**
   ```typescript
   // src/agent/ParallelExecutor.ts
   class ParallelExecutor {
     async executeTools(tools: Tool[], context: Context): Promise<ToolResult[]> {
       // Identify independent tools
       const independent = this.findIndependentTools(tools);
       
       // Execute in parallel batches
       const results = [];
       for (const batch of this.createBatches(independent)) {
         const batchResults = await Promise.all(
           batch.map(tool => tool.execute(context))
         );
         results.push(...batchResults);
       }
       
       return results;
     }
   }
   ```

2. **Streaming LLM Responses**
   ```typescript
   // src/llm/StreamingOllamaClient.ts
   class StreamingOllamaClient extends OllamaClient {
     async *analyzeStream(prompt: string): AsyncGenerator<string> {
       // Stream tokens as they're generated
       const response = await this.ollama.generate({
         model: this.model,
         prompt,
         stream: true
       });
       
       for await (const chunk of response) {
         yield chunk.response;
       }
     }
   }
   ```

3. **Smarter Caching**
   ```typescript
   // src/cache/SmartCache.ts
   class SmartCache extends RCACache {
     // Cache partial results
     async cacheIntermediateResults(
       errorHash: string,
       step: 'parse' | 'hypotheses' | 'validation' | 'final',
       data: any
     ): Promise<void>;
     
     // Reuse partial results for similar errors
     async getPartialResults(errorHash: string): Promise<PartialResult | null>;
   }
   ```

4. **Model Optimization**
   ```typescript
   // Consider smaller, faster models for specific tasks
   const MODEL_CONFIG = {
     hypothesisGeneration: 'deepseek-r1-7b',  // Current
     fixGeneration: 'codellama-13b',          // Specialized for code
     validation: 'mistral-7b',                // Fast, accurate
     explanation: 'deepseek-r1-7b',           // Current
   };
   ```

**Success Metrics (Already Exceeded!):**
- ✅ Median latency: 10.35s (already 88% faster than 90s target!)
- ✅ P90 latency: <20s (achieved)
- Cache hit rate: 60% → 80% (nice to have)
- First response (streaming): <3s (nice to have)

**Verdict:** Performance is NOT a bottleneck. Skip this unless bored.

**Deliverables:**
- [ ] ParallelExecutor.ts
- [ ] Streaming response support
- [ ] SmartCache with partial results
- [ ] Multi-model configuration
- [ ] Performance monitoring dashboard

---

### 3.7: Accuracy Testing & Validation
**Priority:** 🔴 CRITICAL  
**Goal:** Systematically measure and improve accuracy

**Tasks:**
1. **Golden Test Suite Expansion**
   ```typescript
   // tests/golden/android-golden-suite.ts
   const GOLDEN_TESTS = [
     // Current: 7 test cases
     // Target: 100+ test cases covering:
     // - All 26 error types
     // - Multiple scenarios per type
     // - Edge cases and rare errors
     // - Real-world examples from Stack Overflow
   ];
   ```

2. **Automated Accuracy Benchmarking**
   ```typescript
   // scripts/accuracy-benchmark.ts
   class AccuracyBenchmark {
     async runBenchmark(): Promise<BenchmarkResult> {
       const results = await Promise.all(
         GOLDEN_TESTS.map(test => this.testCase(test))
       );
       
       return {
         accuracy: this.calculateAccuracy(results),
         specificityScore: this.calculateSpecificity(results),
         fixCorrectness: this.calculateFixCorrectness(results),
         confidenceCalibration: this.calculateCalibration(results),
       };
     }
     
     private calculateAccuracy(results: TestResult[]): number {
       // Compare LLM output to golden answer
       // Use semantic similarity (embeddings)
       // Must match key concepts (version, file, fix)
     }
   }
   ```

3. **A/B Testing Framework**
   ```typescript
   // src/testing/ABTesting.ts
   class ABTestingFramework {
     // Test prompt variations
     async comparePrompts(
       promptA: string,
       promptB: string,
       testCases: TestCase[]
     ): Promise<Comparison> {
       // Run both prompts on same test cases
       // Measure accuracy, latency, user preference
       // Statistical significance testing
     }
   }
   ```

**Success Metrics:**
- Golden test coverage: 7 → 100+ cases
- Accuracy on golden tests: 50% → 90%+
- Test automation: 100% automated nightly runs
- Regression detection: <1 day to detect accuracy drops

**Deliverables:**
- [ ] 100+ golden test cases
- [ ] Automated accuracy benchmark suite
- [ ] A/B testing framework
- [ ] Nightly accuracy reports
- [ ] Regression alerts

---

## Week 7-8: Learning & Iteration

### 3.8: Community-Driven Knowledge Base (Fun Experiment!)
**Priority:** 🟢 MEDIUM  
**Impact:** Crowdsource fixes from user community
**Note:** Since this is a hobby project, we can experiment with fun community features without worrying about moderation costs or legal stuff!

**Tasks:**
1. **Fix Contribution System**
   ```typescript
   // src/community/ContributionSystem.ts
   class FixContribution {
     async submitFix(
       errorHash: string,
       fix: UserSubmittedFix,
       userId: string
     ): Promise<void> {
       // Store in pending contributions
       await this.db.storePendingContribution({
         errorHash,
         fix,
         userId,
         submittedAt: new Date(),
         status: 'pending_validation'
       });
       
       // Auto-validate if user has high reputation
       if (await this.getUserReputation(userId) > 80) {
         await this.autoApproveFix(fix);
       }
     }
     
     async validateContribution(contributionId: string): Promise<void> {
       // Community voting
       // Admin review
       // Automated testing
     }
   }
   ```

2. **Fix Ranking & Quality**
   ```typescript
   // src/community/FixRanking.ts
   class FixRanking {
     rankFixes(fixes: Fix[]): Fix[] {
       return fixes.sort((a, b) => {
         const scoreA = this.calculateScore(a);
         const scoreB = this.calculateScore(b);
         return scoreB - scoreA;
       });
     }
     
     private calculateScore(fix: Fix): number {
       let score = 0;
       
       // User reputation
       score += fix.submitter.reputation * 0.3;
       
       // Upvotes
       score += fix.upvotes * 0.25;
       
       // Success rate (how often applied and worked)
       score += fix.successRate * 0.25;
       
       // Recency (newer fixes preferred)
       score += this.recencyScore(fix.submittedAt) * 0.2;
       
       return score;
     }
   }
   ```

3. **Reputation System**
   ```typescript
   // src/community/ReputationSystem.ts
   class ReputationSystem {
     async updateReputation(userId: string, action: Action): Promise<void> {
       const points = {
         fix_accepted: +10,
         fix_rejected: -5,
         fix_upvoted: +2,
         fix_downvoted: -1,
         fix_applied_successfully: +15,
         fix_applied_failed: -10,
       };
       
       await this.db.incrementReputation(userId, points[action.type]);
     }
   }
   ```

**Success Metrics:**
- Contribution rate: 10+ fixes/week after 3 months
- Approval rate: 70%+ of submissions accepted
- Community size: 1000+ active users in 6 months

**Deliverables:**
- [ ] Fix contribution system
- [ ] Community voting mechanism
- [ ] Reputation system
- [ ] Fix marketplace UI in extension
- [ ] Moderation tools

---

### 3.9: Continuous Learning from Production
**Priority:** 🟢 MEDIUM  
**Impact:** Agent improves automatically over time
**Privacy:** All learning is local-only! No telemetry, no cloud upload, your code never leaves your machine

**Tasks:**
1. **Feedback Loop Integration (100% Local)**
   ```typescript
   // src/learning/FeedbackLoop.ts
   class ContinuousLearning {
     async processFeedback(): Promise<void> {
       // Every week, analyze feedback
       const feedback = await this.db.getRecentFeedback('7d');
       
       // Identify patterns in negative feedback
       const issues = this.identifyIssues(feedback);
       
       // Generate improved prompts
       const improvedPrompts = await this.generateBetterPrompts(issues);
       
       // A/B test improvements
       await this.abTest(improvedPrompts);
       
       // Deploy if better
       if (await this.isBetter(improvedPrompts)) {
         await this.deploy(improvedPrompts);
       }
     }
   }
   ```

2. **Automated Prompt Tuning**
   ```typescript
   // src/learning/PromptTuner.ts
   class PromptTuner {
     async tunePrompt(
       errorType: ErrorType,
       examples: Example[]
     ): Promise<TunedPrompt> {
       // Use few-shot learning
       // Add successful cases to prompt
       // Remove unsuccessful patterns
       // Optimize for accuracy and specificity
     }
   }
   ```

3. **Analytics Dashboard**
   ```typescript
   // Build internal dashboard showing:
   // - Accuracy trends over time
   // - Common error patterns
   // - Fix success rates
   // - User satisfaction scores
   // - Performance metrics
   ```

**Success Metrics:**
- Automatic improvement: +2% accuracy/month
- Response to issues: <7 days to fix accuracy regressions
- Data utilization: 90%+ of feedback analyzed

**Deliverables:**
- [ ] Continuous learning pipeline
- [ ] Automated prompt tuning
- [ ] Analytics dashboard
- [ ] Weekly accuracy reports
- [ ] Auto-deployment system (with rollback)

---

# 🟡 PHASE 4: Making it Actually Useful
**Duration:** 4-6 weeks  
**Focus:** User experience improvements

---

## Week 1-2: Real-Time Features

### 4.1: Contextual Error Detection
**Priority:** 🔴 CRITICAL  
**Impact:** Catch errors before build

**Tasks:**
1. **Real-Time Error Detection**
   ```typescript
   // vscode-extension/src/features/RealtimeDetection.ts
   class RealtimeErrorDetector {
     // Watch files for errors as user types
     async onFileChange(document: vscode.TextDocument): Promise<void> {
       // Debounce 500ms
       await this.debounce(async () => {
         // Quick syntax check
         const errors = await this.parseDocument(document);
         
         if (errors.length > 0) {
           // Show inline hints
           this.showInlineHints(errors);
           
           // Suggest fixes proactively
           this.suggestFixes(errors);
         }
       });
     }
   }
   ```

2. **Smart Code Actions**
   ```typescript
   // vscode-extension/src/providers/CodeActionProvider.ts
   class RCACodeActionProvider implements vscode.CodeActionProvider {
     provideCodeActions(
       document: vscode.TextDocument,
       range: vscode.Range
     ): vscode.CodeAction[] {
       // If cursor on error line, offer quick fixes
       const error = this.getErrorAtPosition(document, range);
       
       if (error) {
         return [
           this.createFixAction('Apply AI-suggested fix', error),
           this.createExplainAction('Explain this error', error),
           this.createSearchAction('Search similar issues', error),
         ];
       }
       
       return [];
     }
   }
   ```

3. **Inline Error Explanations**
   ```typescript
   // Show explanations directly in editor
   const hoverProvider = new RCAHoverProvider();
   vscode.languages.registerHoverProvider('kotlin', hoverProvider);
   
   class RCAHoverProvider implements vscode.HoverProvider {
     async provideHover(document, position): Promise<vscode.Hover> {
       const error = await this.detectErrorAt(document, position);
       
       if (error) {
         return new vscode.Hover(
           this.formatExplanation(error),
           error.range
         );
       }
     }
   }
   ```

**Success Metrics:**
- Detection speed: <500ms after user stops typing
- False positive rate: <10%
- User adoption: 70%+ enable real-time detection

**Deliverables:**
- [ ] Real-time error detection
- [ ] Code action provider
- [ ] Hover provider with explanations
- [ ] Quick fix suggestions
- [ ] Settings to enable/disable

---

## Week 3-4: Interactive Debugging
**Priority:** 🟡 HIGH  
**Impact:** Conversational debugging (like ChatGPT for errors)

**Why It's Cool:**
Imagine asking "Why does this error happen?" and getting a conversation, not just a static report.

**Tasks:**
1. **Chat Interface for Debugging**
   ```typescript
   // vscode-extension/src/chat/DebugChatProvider.ts
   class DebugChatProvider implements vscode.ChatParticipant {
     async handleChat(
       request: vscode.ChatRequest,
       context: vscode.ChatContext,
       stream: vscode.ChatResponseStream,
       token: vscode.CancellationToken
     ): Promise<void> {
       // User can ask follow-up questions
       // "Why does this error happen?"
       // "Show me an example of the correct code"
       // "What else could cause this?"
       
       const response = await this.agent.chat(request.prompt, context);
       stream.markdown(response);
     }
   }
   ```

2. **Multi-Turn Conversations**
   ```typescript
   // src/chat/ConversationalAgent.ts
   class ConversationalAgent {
     private history: ChatMessage[] = [];
     
     async chat(message: string, context: ChatContext): Promise<string> {
       // Maintain conversation history
       this.history.push({ role: 'user', content: message });
       
       // Use context from previous turns
       const response = await this.llm.generateWithHistory(
         message,
         this.history,
         context
       );
       
       this.history.push({ role: 'assistant', content: response });
       return response;
     }
   }
   ```

3. **Guided Debugging Workflows**
   ```typescript
   // vscode-extension/src/workflows/GuidedDebugging.ts
   class GuidedDebuggingWorkflow {
     // Step-by-step debugging assistant
     async startWorkflow(error: ParsedError): Promise<void> {
       await this.chat.send("I'll help you debug this step by step.");
       
       // Step 1: Understand the error
       await this.explainError(error);
       
       // Step 2: Gather context
       await this.askForContext();
       
       // Step 3: Test hypotheses
       await this.testHypotheses();
       
       // Step 4: Apply fix
       await this.applyFix();
       
       // Step 5: Verify fix
       await this.verifyFix();
     }
   }
   ```

**Success Metrics:**
- Chat engagement: 40%+ of users try chat interface
- Resolution rate: 60%+ of chats lead to fix
- Satisfaction: 4.2+/5.0 rating for chat

**Deliverables:**
- [ ] VS Code chat participant
- [ ] Conversational agent with memory
- [ ] Guided debugging workflows
- [ ] Chat history persistence
- [ ] Export chat to markdown

---

## Week 5-6: Fun Experimental Features

### 4.5: Visual Debugging
**Priority:** 🟢 MEDIUM  
**Impact:** See what's happening, not just read text

**Tasks:**
1. **Dependency Graph Visualization**
   ```typescript
   // Show pretty graph of dependencies
   // Red nodes = conflicts
   // Yellow = outdated
   // Green = all good
   ```

2. **Error Timeline**
   ```typescript
   // Show when error first appeared
   // What code changes might have caused it
   // Previous attempts to fix it
   ```

3. **Code Impact Visualization**
   ```typescript
   // Highlight affected files in file tree
   // Show call graph
   // Visualize where error propagates
   ```

**Deliverables:**
- [ ] Interactive dependency graph
- [ ] Error timeline view
- [ ] Code impact visualizer

---

### 4.6: Educational Features
**Priority:** 🟢 MEDIUM  
**Impact:** Learn while debugging

**Tasks:**
1. **ELI5 Mode**
   ```typescript
   // Explain errors in simple terms
   // Use analogies
   // No jargon
   // Perfect for juniors
   ```

2. **Deep Dive Mode**
   ```typescript
   // For when you want ALL the details
   // Technical explanations
   // Compiler behavior
   // Source code analysis
   // Related concepts
   ```

3. **Learning Notes**
   ```typescript
   // Save lessons learned
   // Build personal knowledge base
   // Track progress
   ```

**Deliverables:**
- [ ] ELI5 mode
- [ ] Deep dive mode  
- [ ] Personal learning tracker

---

# 🎨 PHASE 5: Experimental Fun Stuff (The Best Part!)
**Duration:** Ongoing (forever!)  
**Focus:** Try cool ideas without pressure, monetization concerns, or corporate nonsense  
**Mindset:** This is where we get to be creative and try stuff that big companies can't/won't  
**Examples:** Multi-model ensembles, autonomous code fixes, AI pair programming, whatever sounds fun!

---

## Experiment 1: Multi-Model Ensemble

**Idea:** Use multiple LLMs and combine their answers
```typescript
// Get 3 different opinions
const results = await Promise.all([
  deepseek.analyze(error),   // Good reasoning
  codellama.analyze(error),  // Good at code
  mistral.analyze(error),    // Fast and decent
]);

// Combine results (voting, averaging, etc.)
const best = combineResults(results);
```

**Why:** Might improve accuracy by consensus  
**Risk:** 3x slower and more complex

---

## Experiment 2: Autonomous Fix Agent

**Idea:** Agent that can fix errors WITHOUT human input
```typescript
// Fully autonomous workflow:
1. Detect error
2. Analyze root cause
3. Generate fix
4. Apply fix to code
5. Run tests
6. Commit if tests pass
```

**Why:** Sounds awesome, like having a robot pair programmer  
**Risk:** Could break things, need strong safety checks

---

## Experiment 3: Code Review Agent

**Idea:** Analyze code changes BEFORE they cause errors
```typescript
// On every file save:
1. Check for potential errors
2. Validate version compatibility
3. Detect code smells
4. Suggest improvements
```

**Why:** Prevention better than cure  
**Risk:** Annoying if too many false positives

---

## Experiment 4: Multi-Language Support

**Idea:** Support TypeScript, Python, etc.
```typescript
// Add parsers for:
- TypeScript/JavaScript (React errors, npm issues)
- Python (Django, Flask, pip issues)
- Rust (borrow checker errors)
- Go (goroutine issues)
```

**Why:** Learn about other languages, help more people  
**Risk:** Each language needs custom knowledge base

---

## Experiment 5: Community Knowledge Base

**Idea:** Users can contribute fixes
```typescript
// GitHub-style workflow:
1. User finds good fix
2. Submits to community database
3. Others vote on quality
4. High-rated fixes shown to everyone
```

**Why:** Crowdsource knowledge, help community  
**Risk:** Need moderation, quality control

---

# 📊 Success Metrics (Hobby Project Edition)

**Focus on learning and actual value, not vanity metrics**

### What Actually Matters
| Metric | Current (MVP Test) | Target |
|--------|-------------------|--------|
| Diagnosis Accuracy | 100% ✅ | 100% (maintain) |
| Solution Usability | 40% | 90%+ |
| Helps Me Debug | Sometimes | Most of the time |
| Fun to Work On | Yes | Hell yes |
| Learning New Tech | Active | Active |

### Nice to Have (But Not Critical)
| Metric | Current | Target |
|--------|---------|--------|
| GitHub Stars | 0 | 100+ |
| Active Users | 1 (me) | 10-50 friends |
| Performance | 10.35s ✅ | Already excellent! |

### Don't Care About
- ❌ Revenue (it's free!)
- ❌ Enterprise customers
- ❌ Market share
- ❌ Investors

---

# 🛠️ Tech Stack (Hobby Project)

## Current Setup (LLM/Vector DB Focused)
- **LLM:** DeepSeek-R1-Distill-Qwen-7B (~5GB) - Reasoning model for RCA
  - Strength: Chain-of-thought reasoning, code understanding
  - Alternative models: CodeLlama, Mistral, Llama 3
- **Vector Database:** ChromaDB (local, persistent)
  - Embeddings: all-MiniLM-L6-v2 (default, can upgrade to bge-large)
  - Collections: error patterns, version knowledge, few-shot examples
  - Search: Semantic similarity + metadata filtering
- **RAG Pipeline:** 
  - Error → Embed → ChromaDB query → Top-K retrieval → LLM context
  - Hybrid: Exact match (keywords) + Semantic search (embeddings)
- **Hardware:** RTX 3070 Ti (8GB VRAM) + Ryzen 5 5600x
  - LLM inference: ~3-5 tokens/sec (depends on model)
  - Embedding: ~100 docs/sec
- **Framework:** TypeScript + Node.js
- **Extension:** VS Code Extension API
- **Testing:** Jest

## LLM/Vector DB Architecture
```
User Error Input
    ↓
[Error Parser] → Extract structured data
    ↓
[Embedding Service] → Convert to vector
    ↓
[ChromaDB] → Retrieve similar errors, versions, examples (RAG)
    ↓
[Prompt Engine] → Build context with RAG results + few-shot examples
    ↓
[LLM (DeepSeek-R1)] → Reason about error + generate fix (Chain-of-Thought)
    ↓
[Output Validator] → Check JSON structure, code validity
    ↓
Fix Presented to User
```

## Key LLM/Vector DB Techniques Used
1. **Retrieval-Augmented Generation (RAG)**: Combine LLM with external knowledge base
2. **Few-Shot Learning**: Dynamic example retrieval based on error similarity
3. **Chain-of-Thought Prompting**: Leverage DeepSeek-R1's reasoning capabilities
4. **Structured Output Generation**: Force JSON schema compliance for consistency
5. **Semantic Search**: Vector embeddings for intelligent knowledge retrieval
6. **Hybrid Retrieval**: Combine keyword (BM25) + semantic (vector) search
7. **Prompt Engineering**: Error-type specific prompts with constraints and examples

---

# 🎯 Priority Matrix (Updated with MVP Test Data)

## Do First (Proven High Impact)
1. 🔴 **Better prompts with specificity** (40% → 90% usability)
   - MVP test: Diagnosis perfect, solutions too vague
   - Add: exact files, version numbers, code snippets
   
2. 🔴 **Domain knowledge database** (enable version suggestions)
   - MVP test: Couldn't suggest valid AGP versions
   - Add: AGP 7.x-9.x, Kotlin versions, compatibility matrix
   
3. 🔴 **Fix generation with code diffs** (0% → 85% code examples)
   - MVP test: No before/after code shown
   - Generate actual diffs, not just text descriptions
   
4. 🔴 **File path resolution** (30% → 95% accuracy)
   - MVP test: Said "build.gradle", actual file is "libs.versions.toml"
   - Add: intelligent file detection from project structure
   
5. 🟡 **More MVP project tests** (validate improvements)
   - Test Kotlin errors, Compose errors, XML errors
   - Build comprehensive real-world dataset

## Do Later (Cool but Not Urgent)
6. 🟢 Real-time error detection
7. 🟢 Chat interface
8. 🟢 Visual debugging
9. 🟢 Educational modes
10. ~~Latency reduction~~ (already excellent at 10.35s!)

## Maybe Someday (Experiments)
11. 🔵 Autonomous fixes
12. 🔵 Code review agent
13. 🔵 Multi-language support
14. 🔵 Community knowledge base

## Definitely Not (Too Complex for Hobby)
- ❌ Enterprise features
- ❌ SSO/Authentication
- ❌ Multi-tenancy
- ❌ Custom model fine-tuning
- ❌ Kubernetes deployment
- ❌ Compliance (GDPR, SOC 2, etc.)
- ❌ Audit logging
- ❌ Cost management
- ❌ SLA monitoring

---

# 🛠️ Tech Stack (Hobby Project)

## Current Setup (Works Fine)
- **LLM:** DeepSeek-R1-Distill-Qwen-7B (~5GB)
- **Hardware:** RTX 3070 Ti + Ryzen 5 5600x
- **Database:** ChromaDB (local)
- **Framework:** TypeScript + Node.js
- **Extension:** VS Code Extension API
- **Testing:** Jest

## Potential Upgrades (When Needed)
- **LLM:** Try different models (CodeLlama, Mistral, Llama 3)
- **Hardware:** RTX 4090 if serious about performance
- **Database:** Keep ChromaDB (simple, works)
- **Deployment:** GitHub Releases for distribution

## What NOT to Add
- ❌ Microservices (overkill)
- ❌ Kubernetes (way overkill)
- ❌ Cloud infrastructure (expensive)
- ❌ Complex CI/CD (GitHub Actions is enough)
- ❌ Message queues (not needed)

---

# 📝 Risks & Reality Checks

## Hobby Project Risks

### Risk: Lose Interest
**Mitigation:**
- Work on fun features when motivation drops
- Take breaks, come back refreshed
- Share progress to stay engaged
- Remember why you started

### Risk: Scope Creep
**Mitigation:**
- Focus on accuracy first
- Say no to feature requests
- Finish Phase 3 before Phase 4
- Keep it simple

### Risk: Accuracy Plateau
**Mitigation:**
- Accept that 80% might be the limit
- That's still super useful!
- Focus on edge cases
- Try different models

### Risk: Time Constraints
**Mitigation:**
- It's okay to take months/years
- No deadlines, no pressure
- Progress > perfection
- Even slow progress is progress

---

# 🏆 Success = Learning + Working Product

**After 6-12 months, success looks like:**

1. **Learned a TON**
   - AI/LLM integration ✅
   - VS Code extension development ✅
   - Vector databases ✅
   - Agent reasoning patterns ✅
   - TypeScript best practices ✅

2. **Built Something Useful**
   - Actually helps debug Android errors
   - 80%+ accuracy on common issues
   - Saves time on real projects
   - Friends/colleagues want to use it

3. **Had Fun**
   - Enjoyed the journey
   - Proud of the result
   - No burnout
   - Learned from failures

4. **Optional Bonus**
   - Open sourced project
   - 100+ GitHub stars
   - Small community using it
   - Featured in newsletters/blogs

**The Real Goal:** Build something cool while learning cutting-edge tech. Everything else is bonus! 🚀

---

**Roadmap Version:** 3.0 (Hobby Edition)  
**Last Updated:** December 25, 2025  
**Next Review:** Whenever you feel like it  
**Owner:** You (and it's awesome!)  
**Reminder:** This is for FUN. No stress, no deadlines, just building cool stuff! 🎉
