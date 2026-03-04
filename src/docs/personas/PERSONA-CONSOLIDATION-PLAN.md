**Parent:** [Personas](README.md)

# PersonaUser System Consolidation Plan

**Status**: Phase 0 - Planning
**Goal**: Reduce PersonaUser system from 3544 lines across 3 massive files → clean coordinator pattern
**Method**: Same proven strategy used for SqliteStorageAdapter (2277→842 lines, -63%)

---

## Current State Analysis

### The Three Giants (Context Crash Culprits)

```
PersonaUser.ts:              1,260 lines (main coordinator)
PersonaMessageEvaluator.ts:  1,183 lines (decides if AI should respond)
PersonaResponseGenerator.ts: 1,101 lines (generates AI responses)
────────────────────────────────────────
TOTAL:                       3,544 lines
```

**Problem**: Reading any of these 3 files during context can trigger crashes. They're all ~1200 lines each.

**Root Cause**: Monolithic files with multiple responsibilities mixed together.

---

## Success Pattern from SqliteStorageAdapter

We just successfully applied this exact pattern:

```
BEFORE: SqliteStorageAdapter.ts = 2,277 lines (monolithic)

STRATEGY: Extract manager classes by responsibility
  ├── SqliteSchemaManager     (443 lines) - schema operations
  ├── SqliteQueryExecutor     (600 lines) - read/query operations
  ├── SqliteWriteManager      (513 lines) - write operations
  └── SqliteVectorSearchManager (204 lines) - vector search

AFTER: SqliteStorageAdapter.ts = 842 lines (coordinator)

RESULT: 2,277 → 842 lines (-1,435 lines, -63.0% reduction)
        Zero duplicates, zero legacy code, pure orchestration
```

**Key Insight**: Break monoliths into focused managers, eliminate duplicates, remove legacy cruft.

---

## Phase 0: File Decomposition Strategy

### Priority Order (Biggest Impact First)

#### 🔥 **Target 1: PersonaMessageEvaluator.ts** (1,183 lines)
**Why first**: Gets read on EVERY message evaluation, most frequent context crash source

**Current Responsibilities** (all mixed together):
- Priority calculation
- Message filtering
- Context loading
- RAG building
- Decision making
- Redundancy checking
- Fast response detection
- Event emission

**Extraction Plan**:
```
PersonaMessageEvaluator (1,183 lines)
  └─> Extract Managers:
      ├── MessagePriorityCalculator  (~200 lines)
      │   - calculateMessagePriority()
      │   - isDirectMention()
      │   - isReplyToMe()
      │   - Score calculation logic
      │
      ├── MessageContextLoader       (~250 lines)
      │   - loadChatHistory()
      │   - loadRoomContext()
      │   - loadUserContext()
      │   - buildRAGContext()
      │
      ├── ResponseDecisionEngine     (~300 lines)
      │   - shouldRespondFast()
      │   - shouldRespond()
      │   - Decision logic
      │   - Threshold evaluation
      │
      ├── RedundancyChecker          (~150 lines)
      │   - checkForRedundantResponse()
      │   - findSimilarRecentMessages()
      │   - Similarity scoring
      │
      └── EvaluationEventEmitter     (~150 lines)
          - emitEvaluatingEvent()
          - emitDecidedRespondEvent()
          - emitDecidedSilentEvent()
          - Event payload construction

RESULT: PersonaMessageEvaluator = ~300 lines (pure coordinator)
        Delegates to 5 focused managers
```

**Expected Reduction**: 1,183 → 300 lines (-883 lines, -74.6%)

---

#### 🔥 **Target 2: PersonaResponseGenerator.ts** (1,101 lines)
**Why second**: Gets read on every response generation, second most frequent crash

**Current Responsibilities** (all mixed together):
- RAG context building
- Prompt construction
- System message formatting
- Tool configuration
- API request building
- Response parsing
- Message posting
- Event emission

**Extraction Plan**:
```
PersonaResponseGenerator (1,101 lines)
  └─> Extract Managers:
      ├── RAGContextBuilder          (~250 lines)
      │   - buildChatRAGContext()
      │   - loadRelevantHistory()
      │   - formatContextForPrompt()
      │   - Context windowing
      │
      ├── PromptConstructor          (~200 lines)
      │   - buildSystemPrompt()
      │   - buildUserPrompt()
      │   - formatPersonaPersonality()
      │   - Instruction templating
      │
      ├── ToolConfigurationManager   (~150 lines)
      │   - getAvailableTools()
      │   - formatToolDefinitions()
      │   - Tool schema generation
      │
      ├── AIRequestBuilder           (~200 lines)
      │   - buildTextGenerationRequest()
      │   - setModelConfig()
      │   - setTemperature/TopP/etc
      │   - Request packaging
      │
      ├── ResponseParser             (~150 lines)
      │   - parseAIResponse()
      │   - extractToolCalls()
      │   - handleErrors()
      │   - Response validation
      │
      └── MessagePoster              (~150 lines)
          - postMessageToChat()
          - emitGeneratingEvent()
          - emitPostedEvent()
          - Event emission

RESULT: PersonaResponseGenerator = ~250 lines (pure coordinator)
        Delegates to 6 focused managers
```

**Expected Reduction**: 1,101 → 250 lines (-851 lines, -77.3%)

---

#### ✅ **Target 3: PersonaUser.ts** (1,260 lines)
**Why last**: Already mostly a coordinator, just needs cleanup

**Current State**: Actually pretty good already!
- Already uses 25+ extracted modules
- Main logic is orchestration
- Some legacy code to remove
- Some duplicate helpers to consolidate

**Extraction Plan**:
```
PersonaUser (1,260 lines)
  └─> Consolidation Tasks:
      ├── Remove legacy initialization code
      ├── Remove duplicate helper methods
      ├── Consolidate event subscription logic
      ├── Extract remaining business logic to modules
      └── Pure coordinator pattern

RESULT: PersonaUser = ~400 lines (pure coordinator)
        Clean orchestration, zero duplication
```

**Expected Reduction**: 1,260 → 400 lines (-860 lines, -68.3%)

---

## Phase Execution Plan

### Phase 0.1: PersonaMessageEvaluator Decomposition

**Step 1**: Extract MessagePriorityCalculator
- Create `modules/evaluation/MessagePriorityCalculator.ts`
- Move all priority calculation logic
- Wire into PersonaMessageEvaluator
- Remove duplicates
- Test: Priority scores unchanged

**Step 2**: Extract MessageContextLoader
- Create `modules/evaluation/MessageContextLoader.ts`
- Move all context loading logic
- Wire into PersonaMessageEvaluator
- Remove duplicates
- Test: Context loading works

**Step 3**: Extract ResponseDecisionEngine
- Create `modules/evaluation/ResponseDecisionEngine.ts`
- Move decision logic
- Wire into PersonaMessageEvaluator
- Remove duplicates
- Test: Decisions unchanged

**Step 4**: Extract RedundancyChecker
- Create `modules/evaluation/RedundancyChecker.ts`
- Move redundancy checking
- Wire into PersonaMessageEvaluator
- Remove duplicates
- Test: Redundancy detection works

**Step 5**: Extract EvaluationEventEmitter
- Create `modules/evaluation/EvaluationEventEmitter.ts`
- Move event emission logic
- Wire into PersonaMessageEvaluator
- Remove duplicates
- Test: Events emit correctly

**Step 6**: Consolidation
- Remove all duplicate methods
- Remove legacy code
- Remove no-op methods
- Final result: ~300 line coordinator

**Validation**:
```bash
npm run build:ts  # TypeScript compilation
npm start         # Full deployment
./jtag collaboration/chat/send --room="general" --message="Test evaluation"
# Verify AI responds correctly
```

---

### Phase 0.2: PersonaResponseGenerator Decomposition

**Step 1**: Extract RAGContextBuilder
- Create `modules/generation/RAGContextBuilder.ts`
- Move RAG building logic
- Wire into PersonaResponseGenerator
- Remove duplicates
- Test: RAG context builds correctly

**Step 2**: Extract PromptConstructor
- Create `modules/generation/PromptConstructor.ts`
- Move prompt construction
- Wire into PersonaResponseGenerator
- Remove duplicates
- Test: Prompts format correctly

**Step 3**: Extract ToolConfigurationManager
- Create `modules/generation/ToolConfigurationManager.ts`
- Move tool config logic
- Wire into PersonaResponseGenerator
- Remove duplicates
- Test: Tools configure correctly

**Step 4**: Extract AIRequestBuilder
- Create `modules/generation/AIRequestBuilder.ts`
- Move request building
- Wire into PersonaResponseGenerator
- Remove duplicates
- Test: Requests build correctly

**Step 5**: Extract ResponseParser
- Create `modules/generation/ResponseParser.ts`
- Move parsing logic
- Wire into PersonaResponseGenerator
- Remove duplicates
- Test: Responses parse correctly

**Step 6**: Extract MessagePoster
- Create `modules/generation/MessagePoster.ts`
- Move posting logic
- Wire into PersonaResponseGenerator
- Remove duplicates
- Test: Messages post correctly

**Step 7**: Consolidation
- Remove all duplicate methods
- Remove legacy code
- Remove no-op methods
- Final result: ~250 line coordinator

**Validation**:
```bash
npm run build:ts
npm start
./jtag collaboration/chat/send --room="general" --message="Generate a response"
# Verify AI generates response correctly
```

---

### Phase 0.3: PersonaUser Consolidation

**Step 1**: Audit current state
- Identify remaining business logic
- Find duplicate methods
- Locate legacy code
- Map dependencies

**Step 2**: Extract remaining logic
- Move any business logic to appropriate modules
- Consolidate helper methods
- Remove duplicates

**Step 3**: Clean up initialization
- Simplify constructor
- Consolidate module instantiation
- Remove legacy init code

**Step 4**: Final consolidation
- Remove all duplicates
- Remove all legacy code
- Pure coordinator pattern
- Final result: ~400 line coordinator

**Validation**:
```bash
npm run build:ts
npm start
./jtag collaboration/chat/send --room="general" --message="Full system test"
./jtag collaboration/chat/export --room="general" --limit=20
# Verify entire system works end-to-end
```

---

## Final State (Target)

```
PersonaUser System
├── PersonaUser.ts                    ~400 lines (coordinator)
├── PersonaMessageEvaluator.ts        ~300 lines (coordinator)
├── PersonaResponseGenerator.ts       ~250 lines (coordinator)
│
├── modules/evaluation/
│   ├── MessagePriorityCalculator.ts  ~200 lines
│   ├── MessageContextLoader.ts       ~250 lines
│   ├── ResponseDecisionEngine.ts     ~300 lines
│   ├── RedundancyChecker.ts          ~150 lines
│   └── EvaluationEventEmitter.ts     ~150 lines
│
└── modules/generation/
    ├── RAGContextBuilder.ts          ~250 lines
    ├── PromptConstructor.ts          ~200 lines
    ├── ToolConfigurationManager.ts   ~150 lines
    ├── AIRequestBuilder.ts           ~200 lines
    ├── ResponseParser.ts             ~150 lines
    └── MessagePoster.ts              ~150 lines

BEFORE: 3,544 lines across 3 massive files
AFTER:  ~950 lines in coordinators + ~2,000 lines in focused managers

CONTEXT IMPACT:
  ✅ No single file > 400 lines
  ✅ Each manager focused on ONE responsibility
  ✅ Zero duplicates
  ✅ Zero legacy code
  ✅ No more context crashes when reading code
```

---

## Testing Strategy

### Unit Tests (Per Module)
```bash
npx vitest tests/unit/MessagePriorityCalculator.test.ts
npx vitest tests/unit/MessageContextLoader.test.ts
npx vitest tests/unit/ResponseDecisionEngine.test.ts
npx vitest tests/unit/RedundancyChecker.test.ts
npx vitest tests/unit/RAGContextBuilder.test.ts
npx vitest tests/unit/PromptConstructor.test.ts
# etc...
```

### Integration Tests (Per Phase)
```bash
# After Phase 0.1 (MessageEvaluator)
npx vitest tests/integration/message-evaluation.test.ts

# After Phase 0.2 (ResponseGenerator)
npx vitest tests/integration/response-generation.test.ts

# After Phase 0.3 (PersonaUser)
npx vitest tests/integration/persona-user-full.test.ts
```

### System Tests (End-to-End)
```bash
npm start
./jtag collaboration/chat/send --room="general" --message="Test message 1"
sleep 10
./jtag collaboration/chat/export --room="general" --limit=20
# Verify AI responds correctly

./jtag collaboration/chat/send --room="general" --message="Test message 2"
sleep 10
./jtag collaboration/chat/export --room="general" --limit=20
# Verify AI responds correctly again
```

---

## Success Metrics

### Quantitative
- ✅ PersonaMessageEvaluator: 1,183 → 300 lines (-74.6%)
- ✅ PersonaResponseGenerator: 1,101 → 250 lines (-77.3%)
- ✅ PersonaUser: 1,260 → 400 lines (-68.3%)
- ✅ Total: 3,544 → 950 coordinator lines (-73.2%)
- ✅ Zero files > 400 lines
- ✅ Zero duplicate code
- ✅ Zero legacy code

### Qualitative
- ✅ No context crashes when reading code
- ✅ Each file has single responsibility
- ✅ Easy to understand at a glance
- ✅ Easy to modify safely
- ✅ Easy to test in isolation
- ✅ Maintainable long-term

---

## Risk Mitigation

### Risks
1. **Breaking AI behavior**: Response quality changes
2. **Breaking evaluation logic**: AI stops responding or responds incorrectly
3. **Performance regression**: Slower response times
4. **Test coverage gaps**: Bugs slip through

### Mitigations
1. **Preserve exact logic**: Only move code, don't change behavior
2. **Test after each extraction**: Catch breaks immediately
3. **Keep old code**: Don't delete until new code works
4. **Small incremental commits**: Easy to revert if needed

---

## Timeline Estimate

Based on SqliteStorageAdapter experience (~2 hours total):

- **Phase 0.1** (MessageEvaluator): ~90 minutes
  - 5 manager extractions × ~15 min each
  - Consolidation: ~15 min

- **Phase 0.2** (ResponseGenerator): ~2 hours
  - 6 manager extractions × ~15 min each
  - Consolidation: ~20 min

- **Phase 0.3** (PersonaUser): ~30 minutes
  - Already mostly done
  - Just cleanup and consolidation

**Total**: ~4 hours for complete consolidation

---

## Notes

- **Philosophy**: "Modular first, get working, then easily rework pieces"
- **Pattern**: Extract → Wire → Test → Remove Duplicates → Commit
- **Safety**: TypeScript compilation + precommit hooks catch 95% of issues
- **Validation**: Manual chat testing ensures AI behavior unchanged

---

## Next Steps

1. Read this plan thoroughly
2. Start with Phase 0.1 (MessageEvaluator)
3. Extract MessagePriorityCalculator first
4. Follow the proven pattern from SqliteStorageAdapter
5. Commit after each successful extraction
6. Celebrate when done! 🎉
