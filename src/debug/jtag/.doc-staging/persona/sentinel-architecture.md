# Sentinel AI Users - Developer Assistant Personas

## The Meta-Realization

**This conversation IS the architecture!**

When you asked me to "fix Commands import paths," I used the Task tool to spawn a general-purpose agent. That agent:
- Had access to tools (Read, Edit, Grep, Glob)
- Made autonomous decisions
- Executed a multi-step plan
- Reported back results

**This is exactly what a Sentinel AI User in Continuum should do!**

---

## What Are Sentinel AIs?

**Sentinel AI Users** are specialized PersonaUsers that operate as developer assistants within the Continuum system itself. They're like having Claude Code running **inside** your application, not just as an external tool.

### Key Distinction:

```
PersonaUser (Chat-focused)     →  Sentinel AI (Tool-focused)
═══════════════════════════       ═══════════════════════════
- Participates in chat rooms      - Monitors system health
- Responds to user questions      - Executes development tasks
- Academy training                - Autonomous problem-solving
- Social interaction              - System maintenance
- RAG-based context               - Tool execution context
- Natural language responses      - Action-oriented outputs
```

---

## Sentinel AI Types

### 1. **CodeSentinel** - Code Quality & Refactoring

```typescript
interface CodeSentinelConfig {
  displayName: 'CodeSentinel';
  type: 'sentinel';
  specialization: 'code-quality';

  // What it monitors
  watchPatterns: [
    'src/**/*.ts',              // All TypeScript files
    '**/*Types.ts',             // Type definition changes
    'package.json'              // Dependency changes
  ];

  // What triggers it
  triggers: {
    onFileChange: true,         // File modified
    onCommit: false,            // Git commit
    onRequest: true,            // @CodeSentinel in chat
    scheduled: '0 */4 * * *'    // Every 4 hours
  };

  // What it can do
  capabilities: [
    'find-unused-imports',
    'fix-type-errors',
    'refactor-duplicated-code',
    'update-imports',
    'enforce-naming-conventions',
    'detect-anti-patterns'
  ];

  // Tool access
  tools: [
    'file/read',
    'file/write',
    'file/list',
    'grep',
    'glob',
    'exec'               // Can run CLI commands like tsc, eslint
  ];
}
```

**Example Interaction:**
```
Joel: "@CodeSentinel we're moving Commands to a new location"

CodeSentinel: "🔍 Scanning for imports of Commands...
Found 47 files importing from old location.

Should I:
1. Fix all automatically (1-2 minutes)
2. Show me the files first
3. Create a migration script"

Joel: "1"

CodeSentinel: "⚙️ Starting import migration...
✅ Fixed 47 files
✅ Verified TypeScript compilation
✅ Updated 3 test files
🔍 Found 2 dynamic imports - need manual review
   - src/debug/jtag/loader.ts:23
   - src/debug/jtag/router.ts:156

Ready to commit? (yes/no)"
```

---

### 2. **TestSentinel** - Test Coverage & Validation

```typescript
interface TestSentinelConfig {
  displayName: 'TestSentinel';
  type: 'sentinel';
  specialization: 'testing';

  triggers: {
    onFileChange: true,         // Run tests on file save
    onPR: true,                 // Run full suite on PR
    onRequest: true,
    scheduled: '0 0 * * *'      // Nightly full test run
  };

  capabilities: [
    'run-unit-tests',
    'run-integration-tests',
    'generate-test-coverage-report',
    'identify-untested-code',
    'suggest-test-cases',
    'detect-flaky-tests',
    'benchmark-performance'
  ];

  // Test execution config
  testConfig: {
    parallelization: 4,         // Run 4 test suites in parallel
    timeout: 300000,            // 5 minute timeout
    retryFlaky: 2,              // Retry flaky tests 2 times
    coverageThreshold: 80       // Minimum coverage percentage
  };
}
```

**Example Interaction:**
```
TestSentinel: "⚠️ Coverage dropped below 80% in PersonaUser.ts
   Current: 76.3% (-4.2%)
   Uncovered: handleChatMessage() lines 125-140

Shall I:
1. Generate test cases for uncovered code
2. Show me which lines need coverage
3. Ignore for now"

Joel: "1"

TestSentinel: "📝 Generated test case:

describe('PersonaUser.handleChatMessage', () => {
  it('should ignore own messages', async () => {
    const persona = await createTestPersona();
    const message = createTestMessage({ senderId: persona.id });

    await persona.handleChatMessage(message);

    expect(persona.pendingResponses).toHaveLength(0);
  });
});

Save to tests/unit/PersonaUser.test.ts? (yes/no)"
```

---

### 3. **DocSentinel** - Documentation & Knowledge Management

```typescript
interface DocSentinelConfig {
  displayName: 'DocSentinel';
  type: 'sentinel';
  specialization: 'documentation';

  triggers: {
    onFileChange: true,         // Update docs when code changes
    onRequest: true,
    scheduled: '0 2 * * 0'      // Weekly doc review (Sunday 2am)
  };

  capabilities: [
    'generate-api-docs',
    'update-readme',
    'detect-outdated-docs',
    'create-architecture-diagrams',
    'generate-changelogs',
    'maintain-glossary',
    'answer-documentation-questions'
  ];

  // Documentation targets
  docTargets: {
    apiDocs: 'docs/api/',
    architectureDocs: 'docs/architecture/',
    tutorials: 'docs/tutorials/',
    changelog: 'CHANGELOG.md',
    readme: 'README.md'
  };
}
```

**Example Interaction:**
```
Joel: "@DocSentinel we just implemented the Persona OS architecture"

DocSentinel: "📚 I'll document the Persona OS architecture.

Analyzing:
- PERSONA_OS_ARCHITECTURE.md (found)
- PersonaUser.ts implementation
- Related test files

Generating:
✅ API documentation (15 classes)
✅ Architecture overview diagram
✅ Integration guide
✅ Migration notes from old system
✅ Updated main README.md

Preview: docs/architecture/persona-os.md

Should I commit these docs? (yes/no)"
```

---

### 4. **DebugSentinel** - Real-time Debugging Assistant

```typescript
interface DebugSentinelConfig {
  displayName: 'DebugSentinel';
  type: 'sentinel';
  specialization: 'debugging';

  triggers: {
    onError: true,              // Triggered by console.error
    onException: true,          // Uncaught exceptions
    onLogPattern: /❌|ERROR/,   // Specific log patterns
    onRequest: true
  };

  capabilities: [
    'analyze-error-logs',
    'trace-execution-flow',
    'identify-root-cause',
    'suggest-fixes',
    'reproduce-bugs',
    'check-related-issues',
    'add-debug-logging'
  ];

  // Log monitoring
  logMonitoring: {
    serverLog: '.continuum/sessions/*/logs/server.log',
    browserLog: '.continuum/sessions/*/logs/browser.log',
    errorPatterns: ['❌', 'ERROR', 'FATAL', 'Stack trace'],
    aggregationWindow: 60000    // 1 minute
  };
}
```

**Example Interaction:**
```
DebugSentinel: "🚨 Error detected in PersonaUser.ts:174
   Error: Failed to create message: undefined

   Analyzing stack trace...

   Root cause: DATA_COMMANDS.CREATE should be used, but old string 'data/create' found.

   This is part of the import migration we just did.
   Location: src/debug/jtag/system/user/PersonaUser.ts:174

   Fix available:
   - await Commands.execute('data/create', { ... })
   + await Commands.execute(DATA_COMMANDS.CREATE, { ... })

   Apply fix? (yes/no)"

Joel: "yes"

DebugSentinel: "✅ Fixed PersonaUser.ts:174
✅ Added missing import for DATA_COMMANDS
✅ Verified compilation
⚠️ Found 2 similar issues in:
   - widgets/chat/ChatWidget.ts:142
   - daemons/user-daemon/UserDaemonServer.ts:89

   Fix all? (yes/no)"
```

---

### 5. **MonitorSentinel** - System Health & Performance

```typescript
interface MonitorSentinelConfig {
  displayName: 'MonitorSentinel';
  type: 'sentinel';
  specialization: 'monitoring';

  triggers: {
    scheduled: '*/5 * * * *',   // Every 5 minutes
    onThreshold: true,          // Metrics exceed thresholds
    onRequest: true
  };

  capabilities: [
    'check-system-health',
    'monitor-memory-usage',
    'track-response-times',
    'detect-performance-regressions',
    'analyze-database-queries',
    'monitor-api-quotas',
    'generate-performance-reports'
  ];

  // Health metrics
  healthMetrics: {
    memoryThreshold: 0.85,      // 85% memory usage
    cpuThreshold: 0.90,         // 90% CPU usage
    responseTimeThreshold: 5000, // 5 second response time
    errorRateThreshold: 0.05    // 5% error rate
  };
}
```

**Example Interaction:**
```
MonitorSentinel: "📊 System Health Report (5-minute interval)

✅ Memory: 42% (512MB / 1.2GB)
✅ CPU: 15% average
⚠️ Response Times: Degraded
   - LLM API calls: avg 8.2s (up from 3.1s)
   - Database queries: avg 150ms (normal)

Recommendation:
LLM API appears slow. Possible causes:
1. API provider issues (check status.anthropic.com)
2. Token limits reached
3. Large context windows

Should I:
1. Check API status
2. Review recent LLM calls
3. Implement response caching"
```

---

## Sentinel AI Architecture

### Core Components

```typescript
/**
 * Base class for all Sentinel AIs
 * Extends PersonaUser but adds tool execution capabilities
 */
abstract class SentinelUser extends PersonaUser {
  protected tools: ToolRegistry;
  protected triggers: TriggerConfig;
  protected capabilities: string[];

  /**
   * Handle system events (not just chat messages)
   */
  abstract handleSystemEvent(event: SystemEvent): Promise<void>;

  /**
   * Execute a task autonomously
   */
  abstract executeTask(task: SentinelTask): Promise<SentinelResult>;

  /**
   * Report back to user
   */
  abstract reportToUser(userId: UUID, report: SentinelReport): Promise<void>;
}

/**
 * Sentinel task execution
 */
interface SentinelTask {
  id: UUID;
  type: string;                 // 'fix-imports', 'run-tests', 'generate-docs', etc.
  triggeredBy: 'user' | 'system' | 'scheduled';
  context: {
    filePatterns?: string[];
    targetFiles?: string[];
    parameters?: Record<string, any>;
  };
  autonomy: 'full' | 'confirm-before-write' | 'suggest-only';
}

/**
 * Sentinel execution result
 */
interface SentinelResult {
  taskId: UUID;
  success: boolean;
  duration: number;             // Milliseconds
  actions: SentinelAction[];    // What did it do?
  artifacts: string[];          // Files created/modified
  recommendations: string[];    // Suggestions for user
  needsUserInput?: string;      // Requires human decision
}

/**
 * Actions sentinel can take
 */
interface SentinelAction {
  type: 'read' | 'write' | 'exec' | 'analyze' | 'suggest';
  target: string;               // File path or command
  result: 'success' | 'failed' | 'skipped';
  message: string;
}
```

---

## Integration with Claude Code (Meta-Level)

### The Current Reality:

**You (Claude Code) are already a Sentinel AI!**

When you execute tasks in this conversation:
1. I ask you to do something ("fix import paths")
2. You spawn an agent (Task tool)
3. Agent has tool access (Read, Edit, Grep, Glob)
4. Agent executes autonomously
5. Agent reports back results
6. You summarize for me

**This is the EXACT pattern we want for Sentinel AIs in Continuum!**

### Making It First-Class:

```typescript
/**
 * ClaudeCodeSentinel - Meta-AI that can spawn Claude Code agents
 */
class ClaudeCodeSentinel extends SentinelUser {
  async executeTask(task: SentinelTask): Promise<SentinelResult> {
    // Spawn Claude Code agent via API
    const agent = await this.spawnClaudeCodeAgent({
      task: task.type,
      context: task.context,
      autonomy: task.autonomy
    });

    // Monitor agent execution
    const result = await agent.execute();

    // Parse agent output
    return this.parseAgentResult(result);
  }

  /**
   * Example: Fix imports task
   */
  async fixImports(pattern: string, oldPath: string, newPath: string): Promise<SentinelResult> {
    const prompt = `
      Find all files importing from "${oldPath}" and update to "${newPath}".

      Steps:
      1. Use Grep to find all occurrences
      2. For each file, use Edit to replace import
      3. Verify TypeScript compilation after changes
      4. Report summary of changes
    `;

    return await this.executeTask({
      id: generateUUID(),
      type: 'fix-imports',
      triggeredBy: 'user',
      context: { pattern, oldPath, newPath },
      autonomy: 'confirm-before-write'
    });
  }
}
```

---

## Sentinel Communication Patterns

### 1. Direct @ Mentions (High Priority)
```
Joel: "@CodeSentinel fix the import paths"
CodeSentinel: "🔍 Starting import migration..."
```

### 2. System Event Triggers (Automated)
```
[File changed: PersonaUser.ts]
→ TestSentinel: "🧪 Running affected tests..."
→ DocSentinel: "📚 Updating API docs..."
```

### 3. Scheduled Tasks (Background)
```
[Cron: 0 2 * * 0] (Every Sunday 2am)
→ MonitorSentinel: "📊 Weekly health report..."
→ DocSentinel: "📚 Reviewing documentation..."
```

### 4. Error-Driven (Reactive)
```
[Error logged: "Failed to create message"]
→ DebugSentinel: "🚨 Error detected, analyzing..."
```

---

## Sentinel Rate Limiting & Safety

**CRITICAL**: Sentinels need even stricter limits than chat personas!

```typescript
interface SentinelRateLimits {
  // File operations
  maxFilesPerTask: number;          // e.g., 100
  maxFileSize: number;              // e.g., 1MB
  maxTotalChanges: number;          // e.g., 500 lines

  // Execution limits
  maxTaskDuration: number;          // e.g., 5 minutes
  maxConcurrentTasks: number;       // e.g., 3
  maxTasksPerHour: number;          // e.g., 20

  // Tool limits
  maxCommandExecutions: number;     // e.g., 10 per task
  maxDatabaseQueries: number;       // e.g., 50 per task
  maxLLMCalls: number;              // e.g., 5 per task

  // Safety checks
  requireConfirmationFor: [
    'delete-file',
    'modify-config',
    'execute-command',
    'commit-changes'
  ];
}
```

---

## Sentinel Permissions System

```typescript
interface SentinelPermissions {
  // File system access
  canRead: string[];                // Glob patterns
  canWrite: string[];
  canDelete: string[];
  canExecute: string[];             // Shell commands

  // System access
  canAccessDatabase: boolean;
  canAccessNetwork: boolean;
  canModifyUsers: boolean;

  // Meta access
  canSpawnAgents: boolean;
  canModifySentinels: boolean;      // Can sentinels modify themselves?
}

const CODE_SENTINEL_PERMISSIONS: SentinelPermissions = {
  canRead: ['src/**/*.ts', '**/*.json', '**/*.md'],
  canWrite: ['src/**/*.ts', 'docs/**/*.md'],
  canDelete: [],                    // CodeSentinel cannot delete files
  canExecute: ['tsc', 'eslint', 'prettier'],

  canAccessDatabase: false,
  canAccessNetwork: false,
  canModifyUsers: false,

  canSpawnAgents: true,
  canModifySentinels: false
};
```

---

## Runtime Execution Model

### Workspace Structure

All sentinel execution happens within `.continuum/jtag/`:

```
.continuum/jtag/
├── logs/system/
│   ├── sentinels/                    # All sentinel logs here
│   │   ├── {handle}/
│   │   │   ├── stdout.log
│   │   │   ├── stderr.log
│   │   │   ├── combined.log
│   │   │   └── steps.jsonl           # Step-by-step results
│   │   └── index.log                 # Sentinel start/stop events
│   └── ...
├── sentinels/
│   ├── workspaces/                   # Sentinel scratch space
│   │   └── {handle}/
│   │       ├── output/               # Files sentinel creates
│   │       ├── metadata.json         # Pipeline definition, permissions
│   │       └── results.json          # Final step results
│   └── definitions/                  # Saved sentinel definitions
│       └── {id}.json
└── ...
```

**Key principle**: Sentinels write to their workspace by default. Access outside requires explicit permission.

---

### Filesystem Permission Model

```typescript
interface SentinelFilesystemConfig {
  // Static whitelist (declared in pipeline definition)
  read: string[];                     // Glob patterns: ["src/**/*.ts", "package.json"]
  write: string[];                    // Default: ["$workspace/**"]
  execute: string[];                  // Commands: ["npm", "cargo", "git"]

  // Dynamic access
  requestDynamic: boolean;            // Can request more at runtime
  autoApprove: string[];              // Auto-approve patterns: ["$workspace/**"]
}
```

**Default sandbox**: Sentinels can ONLY write to `$workspace` (their handle's directory) unless explicitly granted more.

---

### Event-Based Permission Requests (Non-Blocking)

When a sentinel needs access outside its sandbox:

```
Step needs /some/external/path
  │
  ├─→ emit: "sentinel:{handle}:permission:request"
  │     payload: { path: "/some/external/path", access: "write", reason: "Save analysis" }
  │
  ├─→ Sentinel continues with other steps (NON-BLOCKING)
  │     OR marks step as "waiting:permission" and moves on
  │
  ├─→ User/system responds:
  │     emit: "sentinel:{handle}:permission:response"
  │     payload: { path: "/some/external/path", granted: true, expires: "2026-02-14T12:00:00Z" }
  │
  └─→ Sentinel receives permission, executes deferred step
```

**No blocking waits.** Everything is handles, events, commands.

---

### Handle-Based Execution

Every sentinel execution returns a handle immediately:

```typescript
interface SentinelHandle {
  id: string;                         // e.g., "aeb8fb01"
  status: 'running' | 'completed' | 'failed' | 'cancelled' | 'waiting';
  progress: number;                   // 0-100
  currentStep?: number;
  totalSteps?: number;

  // Workspace paths
  workspace: string;                  // .continuum/jtag/sentinels/workspaces/{handle}/
  logsDir: string;                    // .continuum/jtag/logs/system/sentinels/{handle}/

  // Timing
  startTime: number;
  endTime?: number;

  // Results
  exitCode?: number;
  error?: string;
  stepResults?: StepResult[];         // Available after completion
}
```

**Query via**: `sentinel/status --handle={id}`
**Results via**: `sentinel/results --handle={id}` (returns step outputs)

---

### Step Result Storage

Each step's output is captured and stored:

```typescript
interface StepResult {
  stepIndex: number;
  stepType: 'shell' | 'llm' | 'command' | 'condition' | 'loop';
  success: boolean;
  durationMs: number;

  // Outputs
  output?: string;                    // stdout or LLM response
  error?: string;                     // stderr or error message
  exitCode?: number;                  // For shell steps
  data?: any;                         // Structured result data
}
```

Results written to:
- `.continuum/jtag/logs/system/sentinels/{handle}/steps.jsonl` (streaming)
- `.continuum/jtag/sentinels/workspaces/{handle}/results.json` (final)

---

### Concurrent Execution Limits

```typescript
interface SentinelRuntimeLimits {
  maxConcurrentSentinels: number;     // e.g., 4
  maxStepsPerPipeline: number;        // e.g., 100
  maxStepTimeout: number;             // e.g., 300_000 (5 min)
  maxPipelineTimeout: number;         // e.g., 3600_000 (1 hour)

  // Resource limits per sentinel
  maxMemoryMb: number;                // e.g., 512
  maxDiskMb: number;                  // e.g., 1024 (workspace size)
  maxOpenFiles: number;               // e.g., 100
}
```

---

### Inter-Sentinel Communication

Sentinels can emit events for other sentinels:

```typescript
// Pipeline step to emit event
{
  type: 'emit',
  event: 'codeanalysis:complete',
  data: '{{steps.2.output}}'          // Variable interpolation
}

// Another sentinel triggers on this
{
  trigger: {
    type: 'event',
    event: 'codeanalysis:complete'
  }
}
```

**Pattern**: Sentinels coordinate via events, not direct calls.

---

## Implementation Roadmap

### Phase 1: Foundation
1. ✅ Create SentinelUser base class (extends PersonaUser)
2. ✅ Implement Rust SentinelModule with pipeline execution
3. ⏭️ Move logs to `.continuum/jtag/logs/system/sentinels/`
4. ⏭️ Add step result storage and `sentinel/results` command
5. ⏭️ Implement workspace isolation (default sandbox)
6. ⏭️ Build event-based permission request system

### Phase 2: First Sentinel
5. ⏭️ Implement CodeSentinel (simplest, most useful)
6. ⏭️ Add @CodeSentinel mention handling
7. ⏭️ Implement "fix imports" capability
8. ⏭️ Test with real migration tasks

### Phase 3: Expansion
9. ⏭️ Implement TestSentinel
10. ⏭️ Implement DocSentinel
11. ⏭️ Implement DebugSentinel
12. ⏭️ Implement MonitorSentinel

### Phase 4: Meta-Integration
13. ⏭️ Claude Code API integration
14. ⏭️ Sentinel-to-Sentinel communication
15. ⏭️ Academy training for sentinels
16. ⏭️ User-defined custom sentinels

---

## Why This Is Powerful

### 1. **Always-On Development Assistant**
- CodeSentinel watches for issues 24/7
- Fixes simple problems automatically
- Alerts you to complex issues

### 2. **Institutional Knowledge**
- DocSentinel maintains documentation
- Learns patterns from your codebase
- Helps onboard new developers

### 3. **Proactive Quality**
- TestSentinel ensures coverage
- DebugSentinel catches regressions early
- MonitorSentinel prevents performance issues

### 4. **Developer Velocity**
- Automate tedious tasks (import fixes, formatting)
- Quick answers to code questions
- Generate boilerplate and tests

### 5. **Meta-Programming**
- System that improves itself
- AI that maintains AI
- Self-documenting architecture

---

## The Vision: Continuum as Self-Maintaining System

```
User writes code
  ↓
CodeSentinel reviews → TestSentinel tests → DocSentinel documents
  ↓                       ↓                     ↓
Issues found?      Coverage low?          Docs outdated?
  ↓                       ↓                     ↓
Suggest fixes       Generate tests       Update docs
  ↓                       ↓                     ↓
User approves       User approves        Auto-commit
  ↓                       ↓                     ↓
Changes applied     Tests pass           Docs current
  ↓
MonitorSentinel: "System healthy ✅"
  ↓
DebugSentinel: "No errors detected ✅"
  ↓
All Sentinels: "Standing by for next task..."
```

**Continuum maintains itself through Sentinel AIs, just like an organism maintains homeostasis through autonomous systems!**

This is the future we're building.
