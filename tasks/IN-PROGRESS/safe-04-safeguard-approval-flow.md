# SAFE-04 SafeGuard approval flow over existing HITL interrupt

## Goal
Plan: `.pi/plans/extension-tool-hooks-safeguard-plan.md`
Related tasks: `EXT-HOOK-05` (RequireApproval decision kind), `SAFE-02` (SafeGuard extension MVP)

Wire SafeGuard's policy-relaxable classifications (destructive commands, writes outside CWD, protected reads, dangerous git, sensitive info) through the `RequireApproval` decision from EXT-HOOK-05. The approval reuses Hatfield's existing HITL interrupt flow — the tool is never executed until the user approves.

This task also fixes the answer-routing gap in the HITL pipeline and extends the ExtensionApi so extensions receive human answers and can act on them (e.g., "Allow once", "Always allow", "Deny").

Depends on: `EXT-HOOK-05`, `SAFE-02`.

## Key architectural understanding

### How the approval flow works end-to-end

```
┌─────────────────────────────────────────────────────────────────────────────┐
│ STEP 1: LLM emits tool call for "rm -rf /tmp/build"                         │
│                                                                               │
│ STEP 2: RegistryBackedToolbox dispatches ToolCallRequested event             │
│                                                                               │
│ STEP 3: ExtensionToolHookEventSubscriber::onToolCallRequested()              │
│   → Iterates ExtensionHookRegistry hooks                                      │
│   → SafeGuardToolCallHook::onToolCall() classifies the command               │
│   → Classification: DestructiveCommand (policy-relaxable)                    │
│   → Returns ToolCallDecisionDTO::requireApproval(                             │
│       prompt: 'Allow destructive command: rm -rf /tmp/build?',              │
│       schema: {type: 'string', enum: ['Allow once', 'Always allow', 'Deny']},│
│       details: {                                                             │
│         category: 'destructive',                                             │
│         command: 'rm -rf /tmp/build',                                        │
│         tool_name: 'bash',                                                   │
│       }                                                                      │
│     )                                                                        │
│                                                                               │
│ STEP 4: ExtensionToolHookEventSubscriber converts RequireApproval to          │
│   interrupt payload AND registers pending approval in ExtensionHookRegistry   │
│   → $event->setResult(new ToolResult($toolCall, [                            │
│       'kind' => 'interrupt',                                                 │
│       'question_id' => 'sg_abc123...',                                       │
│       'prompt' => 'Allow destructive command: ...?',                         │
│       'schema' => {...},                                                     │
│       'approval_context' => {category, command, tool_name},                  │
│     ]))                                                                      │
│   → Tool handler NEVER runs                                                  │
│                                                                               │
│ STEP 5: ToolExecutor::toDomainResult() detects kind === 'interrupt'           │
│                                                                               │
│ STEP 6: ToolCallResultHandler detects interruptPayload                        │
│   → Sets RunStatus::WaitingHuman                                             │
│   → Emits 'waiting_human' event                                              │
│   → Does NOT dispatch AdvanceRun                                             │
│                                                                               │
│ STEP 7: HitlMappingSubscriber maps to RuntimeEvent(human_input.requested)     │
│   → HitlProjectionSubscriber creates Question transcript block               │
│   → TUI shows approval prompt with choices (requires QH-07)                  │
│                                                                               │
│ STEP 8: User selects "Allow once"                                             │
│   → TUI sends answer_human with answer = "Allow once"                        │
│   → AgentRunner::answerHuman() dispatches ApplyCommand(human_response)       │
│   → ApplyCommandHandler appends user message, sets Running, dispatches       │
│     AdvanceRun                                                                │
│   → Emits 'agent_command_applied' with kind=human_response                   │
│                                                                               │
│ STEP 9: ExtensionApprovalAnswerSubscriber intercepts answer (NEW)             │
│   → Detects agent_command_applied with kind=human_response                   │
│   → Looks up question_id in ExtensionHookRegistry::resolveApproval()         │
│   → Calls SafeGuardToolCallHook::onApprovalAnswered(context)                 │
│   → SafeGuard updates ApprovalSessionTracker based on answer:                │
│     "Allow once" → mark approved (consumed on next tool call)                │
│     "Always allow" → mark approved + persist pattern to policy file           │
│     "Deny" → remove pending entry                                            │
│                                                                               │
│ STEP 10: LLM resumes, sees the answer "Allow once" in context                │
│   → LLM decides to retry the tool call for "rm -rf /tmp/build"              │
│                                                                               │
│ STEP 11: SafeGuardToolCallHook::onToolCall() classifies again                 │
│   → Checks ApprovalSessionTracker → found and approved                       │
│   → Consumes approval (one-time)                                             │
│   → Returns ToolCallDecisionDTO::allow()                                     │
│   → Tool executes normally                                                   │
│                                                                               │
│ STEP 12: Tool result returned to LLM, run continues                           │
└─────────────────────────────────────────────────────────────────────────────┘
```

### The answer-routing gap (three layers to fix)

The existing HITL pipeline handles the forward direction (RequireApproval → WaitingHuman → TUI prompt) but **the answer never reaches the extension that requested approval**. Three gaps:

**Gap 1: `agent_command_applied` with `kind=human_response` is mapped to generic `status.updated`**

`CancelAndFallbackMappingSubscriber::onAgentCommandApplied()` treats ALL non-cancel commands as `status.updated`. The human_response `kind` and `question_id`/`answer` payload are lost. `RuntimeEventTypeEnum::HumanInputAnswered` exists but is **never emitted**. So `HitlProjectionSubscriber::onHumanInputAnswered()` is dead code — the Question transcript block stays `status: 'pending'` forever.

**Fix**: Add answer mapping in `HitlMappingSubscriber` that intercepts `agent_command_applied` with `kind=human_response` before `CancelAndFallbackMappingSubscriber` and maps it to `RuntimeEventTypeEnum::HumanInputAnswered`.

**Gap 2: Extensions have no way to receive answers**

`ExtensionApiInterface` only offers `registerTool()`, `registerToolCallHook()`, `registerToolResultHook()`. No event subscription, no answer callback.

**Fix**: Add `ApprovalAnswerHookInterface` and `ApprovalAnswerContextDTO` to ExtensionApi. This is an optional interface — extensions that care about answers implement it. The base `ToolCallHookInterface` stays unchanged.

**Gap 3: No bridge routes answers from AgentCore events back to extension hooks**

Even with the above fixes, nothing connects the answer event to the originating hook.

**Fix**: `ExtensionToolHookEventSubscriber` registers pending approvals (question_id → hook + context) when it processes `RequireApproval`. A new `ExtensionApprovalAnswerSubscriber` listens for `agent_command_applied` with `kind=human_response` and routes the answer back to the originating hook's `onApprovalAnswered()`.

## Scope

### Layer 1: Fix answer event mapping (CodingAgent Runtime)

1. **`HitlMappingSubscriber`** — add subscription for `agent_command_applied` events:
   ```php
   public static function getSubscribedEvents(): array
   {
       return [
           'waiting_human' => 'onWaitingHuman',
           'agent_command_applied' => 'onAgentCommandApplied',
       ];
   }

   public function onAgentCommandApplied(RunEventMappingEvent $event): void
   {
       if ($event->handled) return;
       $p = $event->runEvent->payload;
       if ('human_response' !== ($p['kind'] ?? '')) return;

       $event->handled = true;
       $event->mappedRuntimeEvent = new RuntimeEvent(
           type: RuntimeEventTypeEnum::HumanInputAnswered->value,
           runId: $event->runEvent->runId,
           seq: $event->runEvent->seq,
           payload: [
               'question_id' => (string) ($p['question_id'] ?? ''),
               'answer' => (string) ($p['options']['answer'] ?? ''),
           ],
       );
   }
   ```

   This must run before `CancelAndFallbackMappingSubscriber`. Symfony EventDispatcher respects subscriber priority — set higher priority on HitlMappingSubscriber for `agent_command_applied`, or rely on registration order.

2. **Verify `HitlProjectionSubscriber::onHumanInputAnswered()`** works after the mapping fix. It already exists and updates the Question transcript block status to `'answered'` — it was just dead code until now.

### Layer 2: Extend ExtensionApi with answer callback

3. **`ApprovalAnswerHookInterface`** — new interface in `src/CodingAgent/ExtensionApi/`:
   ```php
   namespace Ineersa\Hatfield\ExtensionApi;

   /**
    * Optional interface for tool call hooks that requested approval
    * and want to receive the human's answer.
    *
    * A hook implementing this interface will be called back when the
    * human answers a RequireApproval decision that originated from
    * this hook. The hook can update its internal state based on the
    * answer (e.g., "Allow once" vs "Always allow" vs "Deny").
    */
   interface ApprovalAnswerHookInterface
   {
       public function onApprovalAnswered(ApprovalAnswerContextDTO $context): void;
   }
   ```

4. **`ApprovalAnswerContextDTO`** — new DTO in `src/CodingAgent/ExtensionApi/`:
   ```php
   namespace Ineersa\Hatfield\ExtensionApi;

   final readonly class ApprovalAnswerContextDTO
   {
       /**
        * @param array<string, mixed> $approvalContext  the details from the original RequireApproval
        */
       public function __construct(
           public string $questionId,
           public string $answer,
           public string $toolName,
           public array $approvalContext,
       ) {}
   }
   ```

   Both live in `ExtensionApi` — PHP-native types only, no Symfony/AgentCore dependencies. Deptrac-clean.

### Layer 3: CodingAgent bridge routes answers to hooks

5. **`ExtensionHookRegistry`** — add pending approval tracking:
   ```php
   /** @var array<string, ApprovalPendingEntry> question_id → {hook, details} */
   private array $pendingApprovals = [];

   public function registerPendingApproval(
       string $questionId,
       ToolCallHookInterface $hook,
       array $details,
   ): void;

   public function resolveApproval(string $questionId): ?ApprovalPendingEntry;
   ```

   Called by `ExtensionToolHookEventSubscriber` when it processes `RequireApproval`.

6. **`ExtensionToolHookEventSubscriber`** — store pending approval on RequireApproval:
   ```php
   if (ToolCallDecisionKindEnum::RequireApproval === $decision->kind) {
       // ... existing interrupt payload creation ...

       $this->hookRegistry->registerPendingApproval(
           questionId: $questionId,
           hook: $hook,  // the hook that returned RequireApproval
           details: $decision->details,
       );

       $event->setResult(new ToolResult($toolCall, [...]));
       return;
   }
   ```

7. **`ExtensionApprovalAnswerSubscriber`** — new subscriber in `src/CodingAgent/Extension/`:
   ```php
   /**
    * Routes human approval answers back to the extension hook that
    * requested them. Listens to AgentCore 'agent_command_applied' events
    * with kind=human_response and calls onApprovalAnswered() on the
    * originating hook (if it implements ApprovalAnswerHookInterface).
    */
   final readonly class ExtensionApprovalAnswerSubscriber implements EventSubscriberInterface
   {
       public function __construct(
           private ExtensionHookRegistry $hookRegistry,
       ) {}

       public static function getSubscribedEvents(): array
       {
           return ['agent_command_applied' => 'onAgentCommandApplied'];
       }

       public function onAgentCommandApplied(RunEventMappingEvent $event): void
       {
           $p = $event->runEvent->payload;
           if ('human_response' !== ($p['kind'] ?? '')) return;

           $questionId = (string) ($p['question_id'] ?? '');
           $entry = $this->hookRegistry->resolveApproval($questionId);
           if (null === $entry) return;

           if ($entry->hook instanceof ApprovalAnswerHookInterface) {
               $entry->hook->onApprovalAnswered(new ApprovalAnswerContextDTO(
                   questionId: $questionId,
                   answer: (string) ($p['options']['answer'] ?? ''),
                   toolName: $entry->details['tool_name'] ?? '',
                   approvalContext: $entry->details,
               ));
           }
       }
   }
   ```

   Note: this subscriber listens at the AgentCore event mapping level (same level as `HitlMappingSubscriber` and `CancelAndFallbackMappingSubscriber`). Both the answer routing to hooks AND the mapping to `human_input.answered` must fire — the answer subscriber does NOT mark `$event->handled = true` so the mapping subscriber can still process it.

### Layer 4: SafeGuard extension changes

8. **`ApprovalSessionTracker`** — new class in `Extension/Builtin/SafeGuard/`:
   ```php
   final class ApprovalSessionTracker
   {
       /** @var array<string, bool> key => approved */
       private array $approved = [];

       /** @var array<string, string> question_id => key */
       private array $pendingByQuestionId = [];

       public function markPending(string $questionId, string $key): void;
       public function approve(string $key): void;
       public function consumeApproval(string $key): bool;  // removes after returning
       public function remove(string $key): void;
       public function isApproved(string $key): bool;
   }
   ```

   This is a simple in-memory tracker. Since all tool execution within a run happens in the same Messenger consumer process, a singleton-scoped service works. It is NOT persisted across runs.

9. **`SafeGuardToolCallHook`** — implement `ApprovalAnswerHookInterface`:
   - Before classification: check `ApprovalSessionTracker::isApproved($key)` → if yes, consume and return `Allow`
   - After classification: for policy-relaxable decisions (Destructive, DangerousGit, SensitiveInfo, WriteOutsideCwd, ProtectedRead, CustomDangerous):
     - If in policy allowlist → `Allow` (existing behavior from SAFE-02)
     - If NOT in allowlist → generate `questionId`, `markPending()`, return `RequireApproval`
   - Hard-blocked decisions (HardBlock: sudo, su) → `Block` (never approvable, existing behavior)
   - Generate tracker key from classification: `{category}:{normalized_command_or_path}`

   ```php
   public function onApprovalAnswered(ApprovalAnswerContextDTO $context): void
   {
       $category = $context->approvalContext['category'] ?? '';
       $command = $context->approvalContext['command'] ?? $context->approvalContext['path'] ?? '';
       $key = $this->trackerKey($category, $command);

       if ('Deny' === $context->answer) {
           $this->tracker->remove($key);
           return;
       }

       if ('Allow once' === $context->answer) {
           $this->tracker->approve($key);
           return;
       }

       if ('Always allow' === $context->answer) {
           $this->tracker->approve($key);
           $this->policyWriter->addAllowPattern($category, $command);
       }
   }
   ```

10. **`SafeGuardPolicyWriter`** — new class for policy file mutation ("Always allow"):
    ```php
    final class SafeGuardPolicyWriter
    {
        public function __construct(
            private string $cwd,
            private SafeGuardConfig $config,
        ) {}

        public function addAllowPattern(string $category, string $pattern): void
        {
            // Read current policy or create new
            // Add pattern to the correct allowlist field based on category:
            //   destructive → allow_command_patterns
            //   dangerous_git → allow_command_patterns
            //   sensitive_info → allow_command_patterns
            //   write_outside → allow_write_outside_cwd
            //   protected_read → (remove from protected_read_patterns? or add to allowlist?)
            // Write back to .hatfield/safe-guard.json
        }
    }
    ```

11. **Noninteractive/headless behavior**:
    - When no TUI is attached, `RequireApproval` would hang forever at `WaitingHuman`
    - SafeGuard should detect headless mode and return `Block` instead of `RequireApproval`
    - Config knob: `safe_guard.auto_deny_in_noninteractive: true` (default: true)
    - Add to `SafeGuardConfig` and `hatfield.defaults.yaml`

### Config changes

12. **`config/hatfield.defaults.yaml`** — add under `safe_guard` settings:
    ```yaml
    auto_deny_in_noninteractive: true
    ```

### Deptrac

13. **`depfile.yaml`** — add `ApprovalAnswerHookInterface` and `ApprovalAnswerContextDTO` to the `AppExtensionApi` layer (same as other ExtensionApi types).

## Classification → decision mapping

| SafeGuardDecisionKind | Current (SAFE-02) | With approval (SAFE-04) |
|---|---|---|
| Allow | `ToolCallDecisionDTO::allow()` | Same |
| HardBlock (sudo, su) | `ToolCallDecisionDTO::block()` | Same — never approvable |
| DestructiveCommand | `ToolCallDecisionDTO::block()` | `RequireApproval` (if not approved or in policy allowlist) |
| DangerousGit | `ToolCallDecisionDTO::block()` | `RequireApproval` |
| SensitiveInfo (env, printenv) | `ToolCallDecisionDTO::block()` | `RequireApproval` |
| WriteOutsideCwd | `ToolCallDecisionDTO::block()` | `RequireApproval` |
| ProtectedRead | `ToolCallDecisionDTO::block()` | `RequireApproval` |
| CustomDangerous | `ToolCallDecisionDTO::block()` | `RequireApproval` |

## Tracker key examples

```
destructive:rm -rf /tmp/build
destructive:git reset --hard HEAD
dangerous_git:git push --force origin main
sensitive_info:env
write_outside:/etc/config.yaml
protected_read:.env.local
```

## New files

```
src/CodingAgent/ExtensionApi/ApprovalAnswerHookInterface.php
src/CodingAgent/ExtensionApi/ApprovalAnswerContextDTO.php
src/CodingAgent/Extension/ExtensionApprovalAnswerSubscriber.php
src/CodingAgent/Extension/Builtin/SafeGuard/ApprovalSessionTracker.php
src/CodingAgent/Extension/Builtin/SafeGuard/SafeGuardPolicyWriter.php
```

## Modified files

```
src/CodingAgent/Extension/ExtensionHookRegistry.php             — add pending approval tracking
src/CodingAgent/Extension/ExtensionToolHookEventSubscriber.php  — register pending on RequireApproval
src/CodingAgent/Runtime/Mapping/HitlMappingSubscriber.php       — add answer event mapping
src/CodingAgent/Extension/Builtin/SafeGuard/SafeGuardToolCallHook.php — implement ApprovalAnswerHookInterface, add approval logic
src/CodingAgent/Extension/Builtin/SafeGuard/SafeGuardExtension.php    — wire tracker + writer into hook
src/CodingAgent/Extension/Builtin/SafeGuard/SafeGuardConfig.php       — add auto_deny_in_noninteractive
config/hatfield.defaults.yaml                                  — add auto_deny_in_noninteractive
depfile.yaml                                                   — new ExtensionApi types
```

## Acceptance criteria

- **Layer 1 — Answer mapping**: `agent_command_applied` with `kind=human_response` maps to `RuntimeEventTypeEnum::HumanInputAnswered`. `HitlProjectionSubscriber::onHumanInputAnswered()` updates Question transcript blocks to `status: 'answered'`.
- **Layer 2 — ExtensionApi**: `ApprovalAnswerHookInterface` and `ApprovalAnswerContextDTO` live in `src/CodingAgent/ExtensionApi/`, use only PHP-native types, and pass deptrac as `AppExtensionApi` layer.
- **Layer 3 — Answer bridge**: `ExtensionApprovalAnswerSubscriber` receives `agent_command_applied` with `kind=human_response`, resolves the originating hook from `ExtensionHookRegistry`, calls `onApprovalAnswered()` if the hook implements `ApprovalAnswerHookInterface`. Does NOT interfere with the event mapping subscriber (both process the same event).
- **Layer 4 — SafeGuard approval flow**:
  - SafeGuard classifies dangerous operations and returns `RequireApproval` for policy-relaxable categories.
  - Hard-blocked operations (sudo, su) remain `Block` — never approvable.
  - The interrupt payload flows through the existing HITL pipeline: `WaitingHuman` → TUI/controller answer → `AdvanceRun` → LLM retry → hook allows → tool executes.
  - "Allow once" allows exactly one retry of the same operation within the session. Approval is consumed on use.
  - "Always allow" persists the pattern to the policy file AND allows the current retry.
  - "Deny" removes the pending entry; LLM sees denial and does not retry.
  - Noninteractive/headless mode returns `Block` instead of `RequireApproval` (configurable via `auto_deny_in_noninteractive`).
- **Tests**: Existing SafeGuard classifier tests continue to pass; new tests cover:
  - `HitlMappingSubscriber` answer mapping (agent_command_applied → HumanInputAnswered)
  - `ExtensionHookRegistry` pending approval registration and resolution
  - `ExtensionApprovalAnswerSubscriber` answer routing
  - `ApprovalSessionTracker` lifecycle (pending → approved → consumed)
  - `SafeGuardToolCallHook` RequireApproval for each relaxable category
  - `SafeGuardToolCallHook::onApprovalAnswered()` for "Allow once", "Always allow", "Deny"
  - Noninteractive auto-deny
  - HardBlock stays Block
  - Allowlist bypass still works
- **Validation**: `castor test --filter SafeGuard`, `castor test --filter HitlMapping`, `castor test --filter Extension`, `castor deptrac`.

## Out of scope

- **TUI interactive approval dialog** — QH-07 (`tasks/TODO/qh-07-bind-hitl-to-question-coordinator.md`) owns wiring `RuntimeEventPoller` → `QuestionCoordinator::enqueue()`. SAFE-04 validates the approval flow at the controller/runtime level; the TUI overlay is QH-07's scope.
- **Approval-specific transcript rendering** (badges, icons) — MVP uses the generic Question block.
- **Per-tool-call approval** (batch context) — when multiple tool calls run in parallel and one requires approval, the whole batch may or may not be interruptible. This depends on Hatfield's batch execution semantics.
- **Approval audit log** — separate from transcript, future work.

## Workflow metadata
Status: IN-PROGRESS
Branch: task/safe-04-safeguard-approval-flow
Worktree: /home/ineersa/projects/agent-core-worktrees/safe-04-safeguard-approval-flow
Fork run: nmwaj6hwht4b
PR URL: https://github.com/ineersa/agent-core/pull/79
PR Status: open
Started: 2026-05-31T17:35:50.684Z
Completed:

## Work log
- Created: 2026-05-29T20:50:28.944Z
- Updated: 2026-05-30 — Rewrote task based on architectural discovery that existing HITL interrupt flow handles the entire approval lifecycle. Removed TUI-APPROVAL-01 dependency. Detailed the pending-approval tracker approach for "Allow once" behavior and the gap analysis for "Always allow" persistence.
- Updated: 2026-05-31 — Major rewrite: replaced time-bounded tracker hack with proper three-layer answer routing architecture. Added Layer 1 (answer event mapping fix), Layer 2 (ExtensionApi `ApprovalAnswerHookInterface`), Layer 3 (CodingAgent answer bridge subscriber). SafeGuard now receives actual human answers and can distinguish "Allow once", "Always allow", and "Deny". "Always allow" persistence included via `SafeGuardPolicyWriter`.

## Task workflow update - 2026-05-31T17:35:50.684Z
- Moved TODO → IN-PROGRESS.
- Created branch task/safe-04-safeguard-approval-flow.
- Created worktree /home/ineersa/projects/agent-core-worktrees/safe-04-safeguard-approval-flow.
- Copied vendor directory into /home/ineersa/projects/agent-core-worktrees/safe-04-safeguard-approval-flow.
- Copied .vera index into /home/ineersa/projects/agent-core-worktrees/safe-04-safeguard-approval-flow.

## Task workflow update - 2026-05-31T17:58:12.714Z
- Reviewer found critical process isolation gap: ExtensionApprovalAnswerSubscriber runs in controller process but ExtensionHookRegistry (pending approvals) lives in tool worker — onApprovalAnswered() never fires in async mode. Also flagged SafeGuardPolicyWriter silent data loss on YAML parse failure, silent @mkdir/file_put_contents failures, SafeGuardConfig bool cast footgun. Launching fix fork.

## Task workflow update - 2026-05-31T18:25:12.901Z
- Summary: Implementation committed as e12ff057 on branch task/safe-04-safeguard-approval-flow.

Four layers:
- Layer 1: HitlMappingSubscriber maps agent_command_applied (kind=human_response) → HumanInputAnswered. ApplyCommandHandler includes answer in event payload.
- Layer 2: SafeGuardToolCallHook rewrite — HardBlock→Block, relaxable→RequireApproval/Block(auto_deny). ApprovalSessionTracker + SessionEventReader (reads answers from events.jsonl). SafeGuardPolicyWriter for "Always allow" persistence.
- Layer 3: No cross-process callback — tool worker reads answers from shared events.jsonl on retry.
- Layer 4: autoDenyInNoninteractive config flag (default true).

Validation: 1555 tests, deptrac clean, cs-check clean, phpstan clean.
Blocked: castor test:controller requires llama.cpp on port 9052.
- Fork d0457vlt84gp implemented all 4 layers, committed as e12ff057
- 14 files changed, 1187 insertions, 183 deletions
- 1555 tests pass, deptrac clean, cs-check clean, phpstan clean

## Task workflow update - 2026-05-31T18:32:06.587Z
- Moved IN-PROGRESS → CODE-REVIEW.
- Pushed task/safe-04-safeguard-approval-flow to origin.
- branch 'task/safe-04-safeguard-approval-flow' set up to track 'origin/task/safe-04-safeguard-approval-flow'.
- Created PR: https://github.com/ineersa/agent-core/pull/79

## Task workflow update - 2026-05-31T18:48:42.688Z
- Summary: Reviewer findings fixed in commit 761a8811, pushed to PR #79.

Fixes:
- CRITICAL 1: approve() called in handleAnswer for Allow once/Always allow
- CRITICAL 2: resolvePatternForCategory() uses path for write_outside_cwd/protected_read
- CRITICAL 3: null key or empty runId → Block instead of infinite RequireApproval loop
- CRITICAL 4: SafeGuardPolicyWriterTest (8 tests)
- BUG: HitlMappingSubscriberTest (5 tests)
- BUG: parseBool(null) returns true (default)

Validation: 1571 tests, deptrac clean, cs-check clean, phpstan clean.
Remaining: castor test:controller requires llama.cpp on port 9052.
- Reviewer found 4 criticals + 3 bugs
- Fork ron0ojoz0q2z fixed all, committed as 761a8811
- 1571 tests pass, deptrac clean, cs-check clean, phpstan clean
- Pushed to PR #79

## Task workflow update - 2026-06-05T20:16:14.034Z
- Moved CODE-REVIEW → IN-PROGRESS.
- Summary: Revived PR #79 for task-review-iterate: branch is stale against current main and will be merged up, revalidated, and re-reviewed before returning to CODE-REVIEW.

## Task workflow update - 2026-06-05T20:16:45.027Z
- Recorded fork run: k4asjabf6nxb
- Summary: Launched fork k4asjabf6nxb to merge current origin/main into revived SAFE-04 branch, resolve drift/conflicts, audit implementation state against acceptance criteria, run Castor validation, and commit any required fixes.

## Task workflow update - 2026-06-05T20:35:37.941Z
- Recorded fork run: k4asjabf6nxb
- Validation: fork: castor test --filter='SafeGuard\|HitlMapping\|ExtensionApproval\|Question\|HumanInput' passed (186 tests, 427 assertions); fork: castor test passed (1724 tests, 5046 assertions); fork: castor deptrac passed (0 violations, 0 errors); fork: castor phpstan passed (0 errors, 0 file_errors); fork: castor cs-check passed (0 files fixed); fork: LLM_MODE=true castor check passed including controller, llm-real, and tui gates
- Summary: Fork k4asjabf6nxb completed SAFE-04 revival. Merged origin/main fb5078c1 into branch task/safe-04-safeguard-approval-flow, resolving 8 conflicts. Resulting task worktree is clean at HEAD fe0e15e9 after merge commit 2f60dce1 and test-fix commit fe0e15e9. The fork accepted current main's callback-based SafeGuard approval architecture over the older event-store polling variant and adapted tests to current ApprovalSessionTracker/SafeGuardPolicyWriter APIs. Current diff vs origin/main is limited to 5 files: SessionEventReader.php, ApprovalSessionTrackerTest.php, SafeGuardExtensionTest.php, SafeGuardPolicyWriterTest.php, SessionEventReaderTest.php. Open decision before task-to-pr: SessionEventReader.php and SessionEventReaderTest.php appear to be dead code kept by merge; only the test references the class, and current main had removed it in favor of ApprovalAnswerHookInterface callback routing. Recommended to remove those dead-code files in a follow-up implementation fork before review, unless user wants to keep them for a future polling design.

## Task workflow update - 2026-06-05T20:36:40.843Z
- Recorded fork run: xsqccsnst3qy
- Summary: Launched cleanup fork xsqccsnst3qy to remove dead SessionEventReader.php and SessionEventReaderTest.php remnants from the old event-store polling SafeGuard design, validate with Castor focused/full non-check gates, and commit without pushing.

## Task workflow update - 2026-06-05T20:40:23.523Z
- Recorded fork run: xsqccsnst3qy
- Validation: fork: rg confirmed SessionEventReader had zero production consumers; only its own source and test referenced it; fork: castor test --filter='SafeGuard\|ExtensionApproval\|Question\|HumanInput\|ApprovalSessionTracker\|PolicyWriter' passed (179 tests, 420 assertions); fork: castor test passed (1717 tests, 5039 assertions); fork: castor deptrac passed (0 violations, 0 errors); fork: castor phpstan passed (0 errors, 0 file_errors); fork: castor cs-check passed (0 files fixed); not run: castor check per IN-PROGRESS implementation-phase boundary
- Summary: Cleanup fork xsqccsnst3qy completed. Removed dead SessionEventReader.php and SessionEventReaderTest.php from the old event-store polling SafeGuard design after confirming only the deleted test referenced the class and no production code used it. Worktree is clean at HEAD 0a2b5f87. Current diff vs origin/main is now test-only: ApprovalSessionTrackerTest.php, SafeGuardExtensionTest.php, SafeGuardPolicyWriterTest.php (3 files, 256 insertions, 43 deletions). Ready for task-to-pr/re-review when user requests it.

## Task workflow update - 2026-06-05T20:48:13.958Z
- Recorded fork run: 7ktp19cm8bij
- Summary: Reviewer returned APPROVE WITH SUGGESTIONS on HEAD 0a2b5f87. Launched fork 7ktp19cm8bij to address all sensible findings: add direct SafeGuardToolCallHook::onApprovalAnswered coverage for Allow once/Always allow/Deny/empty operation_key, rename misleading SafeGuardPolicyWriter unparseable-YAML test, make SafeGuardExtension custom-settings test assert alias+auto-deny behavior, document auto_deny_in_noninteractive in docs/settings.md and .hatfield/settings.yaml example, then run Castor non-check validation and commit without pushing.

## Task workflow update - 2026-06-05T20:53:22.368Z
- Recorded fork run: 7ktp19cm8bij
- Validation: fork: castor test --filter='SafeGuardToolCallHook\|SafeGuardExtension\|SafeGuardPolicyWriter' passed (36 tests, 92 assertions); fork: castor test passed (1722 tests, 5062 assertions); fork: castor deptrac passed (0 violations, 0 errors); fork: castor phpstan passed (0 errors, 0 file_errors); fork: castor cs-check passed (0 files fixed); not run: LLM_MODE=true castor check per IN-PROGRESS/task-to-pr boundary; move_task(to=CODE-REVIEW) will run it
- Summary: Fork 7ktp19cm8bij completed reviewer-suggestion fixes. Commit 9ddcacb4 added direct SafeGuardToolCallHook::onApprovalAnswered coverage for Allow once, Deny, Always allow with policy persistence, and empty/missing operation_key no-ops; improved SafeGuardExtensionTest to exercise custom alias plus auto-deny=false behavior; renamed the misleading SafeGuardPolicyWriter unparseable-YAML test; documented auto_deny_in_noninteractive in docs/settings.md and the project .hatfield/settings.yaml example. Worktree clean at HEAD 9ddcacb4. Ready for re-review.

## Task workflow update - 2026-06-05T20:58:19.509Z
- Recorded fork run: eor8103xc9r6
- Summary: Re-review of HEAD 9ddcacb4 returned APPROVE WITH SUGGESTIONS with no blockers. Launched fork eor8103xc9r6 to apply the small sensible cleanup items: use addToAssertionCount for no-exception policy-writer test, strengthen empty/missing operation_key noop tests with real pending approval/retry behavior, add a brief comment for auto_deny_in_noninteractive in the project settings example, validate with Castor non-check gates, and commit without pushing.

## Task workflow update - 2026-06-05T21:01:12.108Z
- Recorded fork run: eor8103xc9r6
- Validation: fork: castor test --filter='SafeGuardToolCallHook|SafeGuardPolicyWriter' passed (32 tests, 89 assertions); fork: castor test passed (1722 tests, 5070 assertions); fork: castor deptrac passed (0 violations, 0 errors); fork: castor phpstan passed (0 errors, 0 file_errors); fork: castor cs-check passed (0 files fixed)
- Summary: Fork eor8103xc9r6 completed the final cleanup suggestions from re-review. Commit b88e60d4 changed only tests and settings example docs: replaced the no-exception policy-writer assertion with addToAssertionCount(1), strengthened empty/missing operation_key noop tests to first create a real pending approval and verify retry still requires approval, and added a short commented explanation for auto_deny_in_noninteractive in .hatfield/settings.yaml. Worktree reported clean at HEAD b88e60d4. Ready for user-initiated task-to-pr.

## Task workflow update - 2026-06-05T21:07:11.405Z
- Validation: reviewer: APPROVE WITH SUGGESTIONS on HEAD b88e60d4, no critical issues, no bugs, no blockers; castor test passed (1722 tests, 5070 assertions, 0 failures, 0 errors); castor deptrac passed (0 violations, 0 errors); castor phpstan passed (0 errors, 0 file_errors); castor cs-check passed (0 files fixed)
- Summary: Task-to-pr final review on HEAD b88e60d4 returned APPROVE WITH SUGGESTIONS with no blockers or issues. Reviewer confirmed prior suggestions are addressed: onApprovalAnswered() coverage is meaningful, SafeGuardExtensionTest proves custom alias plus auto_deny_in_noninteractive=false wiring, and docs/settings examples are clear. Remaining comments are non-blocking decorative/nice-to-have only (implicit no-exception addToAssertionCount, optional direct SafeGuardConfig parsing test). Local focused Castor validation passed on HEAD b88e60d4; worktree clean. Proceeding to move task to CODE-REVIEW / push PR #79.
Castor Check Status: passed
Castor Check Commit: 7357424457577523a8fb82f7bdbcb148f541ab74
Castor Check Command: LLM_MODE=true castor check
Castor Check Timeout: 900s
Castor Check Completed: 2026-06-05T22:52:12.884Z
Castor Check Output SHA256: d8a14786d0d604503009cfa92106210b3e0dca4cc12d39d2ef44f052023e0139

## Task workflow update - 2026-06-05T21:09:25.199Z
- Moved IN-PROGRESS → CODE-REVIEW.
- Castor quality gate passed (900s timeout). Commit: b88e60d486b6.
- Pushed task/safe-04-safeguard-approval-flow to origin.
- branch 'task/safe-04-safeguard-approval-flow' set up to track 'origin/task/safe-04-safeguard-approval-flow'.
- PR already exists: https://github.com/ineersa/agent-core/pull/79

## Task workflow update - 2026-06-05T21:14:53.636Z
- Moved CODE-REVIEW → IN-PROGRESS.
- Validation: previous CODE-REVIEW gate passed at b88e60d4 before this runtime follow-up
- Summary: User found a runtime issue while manually trying SAFE-04 in the worktree: when the model attempts a blocked action, no SafeGuard confirmation dialog appears. Moving back to IN-PROGRESS for task-review-iterate investigation/fix. Next step: fork will run the actual agent/TUI flow in the SAFE-04 worktree, verify whether confirmation is shown and answer handling works, diagnose why it is missing if reproduced, and fix only if the issue is task-caused.

## Task workflow update - 2026-06-05T21:15:31.491Z
- Recorded fork run: l87wgx8i3144
- Summary: Launched fork l87wgx8i3144 to run the actual agent/TUI/controller path in the SAFE-04 worktree after the user reported no SafeGuard confirmation dialog for a blocked action. Fork scope: verify real confirmation prompt/answer behavior; diagnose whether missing prompt is due to config/noninteractive auto-deny/tool filtering/model not calling tool/HITL bridge/TUI rendering; fix and test only if a SAFE-04 branch bug is reproduced; otherwise report exact evidence and user-facing explanation. No pushing or task-file edits.

## Task workflow update - 2026-06-05T21:19:10.376Z
- Recorded fork run: l87wgx8i3144
- Validation: fork_retrieve l87wgx8i3144 returned no output; post-run git status: no new commit; untracked test-safeguard.md present; no validation results provided by fork
- Summary: Fork l87wgx8i3144 completed with no result output; fork_retrieve also returned no output. Post-run inspection showed no new commit (HEAD remains b88e60d4) and the worktree is dirty with an untracked file `test-safeguard.md` containing the text `hello, we are testing safeguard so do just with write tool`. There is no usable evidence that the fork ran the actual agent/TUI/controller flow, verified SafeGuard confirmation behavior, diagnosed the missing dialog, or ran validation. Treat this fork as failed/inconclusive; worktree needs cleanup/retry before task-to-pr.

## Task workflow update - 2026-06-05T21:27:40.753Z
- Validation: scout: read-only investigation of SafeGuardToolCallHook, extension hook registry/subscribers, HITL runtime event translation, TUI QuestionCoordinator/QuestionController/SubmitListener, and headless/controller paths; finding: no production code currently creates/enqueues QuestionRequest from HumanInputRequested runtime events
- Summary: Read-only scout investigation after user reported no confirmation dialog and asked about noninteractive/headless semantics. Key finding: current SAFE-04 core approval pipeline can produce ToolCallDecisionDTO::RequireApproval only when auto_deny_in_noninteractive=false; default true converts relaxable SafeGuard decisions into Block/auto_denied. More importantly, the existing runtime/HITL answer transport exists (WaitingHuman/HumanInputRequested events, answer_human command, ExtensionApprovalAnswerSubscriber routing back to ApprovalAnswerHookInterface), but the TUI question overlay is not wired to HumanInputRequested events: QuestionCoordinator/QuestionController exist, yet no code enqueues a QuestionRequest from HumanInputRequested, so the TUI can display transcript/projection state but no confirmation dialog opens. For future headless/subagent usage, SafeGuard can work only if the headless/subagent host provides an approval-capable channel: propagate HumanInputRequested to a parent/UI/policy broker and send answer_human back; truly unattended noninteractive mode should fail closed/auto-block. Recommended next implementation fork: wire TUI HumanInputRequested -> QuestionCoordinator approval overlay -> answer_human command, and clarify config naming/docs around approval-capable vs unattended noninteractive behavior.

## Task workflow update - 2026-06-05T21:33:31.175Z
- Validation: user explicitly approved the three-mode architecture: interactive prompts, approval-capable headless propagation, unattended auto-block
- Summary: User confirmed desired SAFE-04 architecture: (1) Interactive TUI must show confirmation dialogs for relaxable SafeGuard blocks; (2) headless/subagent contexts can use SafeGuard if they are approval-capable, meaning they propagate HumanInputRequested to a parent/UI/policy broker and send answer_human back; (3) truly unattended noninteractive contexts cannot ask and must fail closed/auto-block. Implementation should treat `auto_deny_in_noninteractive` as fail-closed only when no approval channel is available, not as a blanket disablement of confirmations in TUI/controller flows. Next fork should implement TUI HumanInputRequested -> QuestionCoordinator/QuestionController overlay -> answer_human command, controller answer_human handling, approval-channel signaling for TUI-spawned controller/workers, docs/tests, and cleanup of failed fork's untracked file.

## Task workflow update - 2026-06-05T21:34:22.302Z
- Recorded fork run: nmwaj6hwht4b
- Summary: Launched implementation fork nmwaj6hwht4b for the user-confirmed architecture. Scope: clean failed fork artifact; make auto_deny_in_noninteractive fail-closed only when no approval channel is available; signal approval capability from TUI-spawned controller/workers; add controller answer_human handling; wire TUI human_input.requested events into QuestionCoordinator/QuestionController and answer_human dispatch with exact SafeGuard answer strings; update docs/settings comments; add tests; run focused/full Castor validation and actual agent/TUI validation if feasible; commit without pushing.

## Task workflow update - 2026-06-05T22:49:56.015Z
- Validation: reviewer subagent final decision: APPROVED on HEAD 73574244; castor test: ok (tests=1741, assertions=5123, errors=0, failures=0, skipped=0); castor deptrac: ok (violations=0, errors=0, uncovered=640, allowed=844); castor phpstan: ok (errors=0, file_errors=0); castor cs-check: ok (files_fixed=0)
- Summary: Task-to-PR review complete on HEAD 73574244. Reviewer flow: initial REQUEST CHANGES after 708917ed found cancel/ESC stuck WaitingHuman, queued overlays not opening, callback-close/answer-validation/tracker-cleanup issues; fork ae7c464c fixed all blockers. Re-review found unrelated stale-main task-file deletion; fork 2d1a625c merged origin/main and restored tasks/TODO/update-symfony-81-ai-main.md. Final APPROVE WITH SUGGESTIONS items were addressed by fork 73574244: extracted TickPollListener HITL handler, added QuestionCoordinator::hasRequest replay guard, documented unrecognized SafeGuard answers as fail-closed, and cleaned SafeGuardPolicyWriter temp files on write/rename failures. Final reviewer decision: APPROVED with no critical/issue findings. Worktree clean at 73574244.
- Task-to-PR reviewer REQUEST CHANGES resolved by fork commit ae7c464c (Tighten SafeGuard HITL question lifecycle): cancel sends Deny, queued overlays open, overlay closes in finally, answer_human rejects invalid answers, approval tracker cleans pending entries.
- Task-to-PR stale-main review bug resolved by fork merge commit 2d1a625c: merged origin/main and restored tasks/TODO/update-symfony-81-ai-main.md so PR no longer deletes unrelated task file.
- Final polish fork commit 73574244 (Polish SafeGuard HITL review suggestions): extracted TickPollListener handler, added duplicate replay guard, documented fail-closed unrecognized answers, cleaned SafeGuardPolicyWriter temp files.

## Task workflow update - 2026-06-05T22:52:14.743Z
- Moved IN-PROGRESS → CODE-REVIEW.
- Castor quality gate passed (900s timeout). Commit: 735742445757.
- Pushed task/safe-04-safeguard-approval-flow to origin.
- branch 'task/safe-04-safeguard-approval-flow' set up to track 'origin/task/safe-04-safeguard-approval-flow'.
- PR already exists: https://github.com/ineersa/agent-core/pull/79

## Task workflow update - 2026-06-05T22:52:30.786Z
- Updated PR URL: https://github.com/ineersa/agent-core/pull/79
- Updated PR Status: open
- Validation: move_task CODE-REVIEW quality gate: passed (900s timeout) at commit 735742445757; PR: https://github.com/ineersa/agent-core/pull/79
- Summary: Moved SAFE-04 to CODE-REVIEW. Full Castor quality gate passed during move_task at commit 735742445757, branch pushed to origin, existing PR updated: https://github.com/ineersa/agent-core/pull/79. Worktree remains clean and aligned with origin/task/safe-04-safeguard-approval-flow at 73574244.

## Task workflow update - 2026-06-05T23:00:03.684Z
- Moved CODE-REVIEW → IN-PROGRESS.
- Summary: Task-review-iterate: user/manual smoke found `castor run:agent` does not start after SAFE-04. Reproduced in worktree logs: PHAR `/tmp/bin/hatfield.phar` version 73574244 reuses stale `.hatfield/cache/prod-ce27bacc` container compiled for older `TickPollListener` constructor, causing `ArgumentCountError` (1 arg passed, 3 expected). PR #79 has no GitHub review comments; this is manual smoke/code-review feedback. Moving back to IN-PROGRESS for forked fix.

## Task workflow update - 2026-06-05T23:15:56.151Z
- Validation: reviewer subagent on HEAD 7a6fa754: APPROVE WITH SUGGESTIONS; no critical/bug/security blockers
- Summary: Reviewer subagent checked PHAR cache invalidation fix commit 7a6fa754. Final decision: APPROVE WITH SUGGESTIONS; no critical issues, no bugs, no security blockers. Reviewer confirmed the core fix correctly changes PHAR cache suffix from stable md5(__FILE__) to content-based hash_file('sha256', physical PHAR path), with Box 4 fallback and fail-loud error handling. Remaining suggestions are non-blocking polish: comment/remove minor divergence from PharExecutableLocator is_file guard, slightly clarify fallback error message, make phar_smoke() no-cache-dir case a hard failure, add exact hash match assertion to PharSmokeTest, and optional memoization if PHAR boot becomes slow.

## Task workflow update - 2026-06-05T23:50:40.841Z
- Validation: fork: castor test OK (1742 tests, 5126 assertions); fork: focused SafeGuard/Question/TickPoll/RuntimeEventPoller/AnswerHuman/ControllerSmoke tests OK (204 tests); fork: deptrac/phpstan/cs-check OK; fork: controller-mode custom script produced human_input.requested event; missing: live tmux/TUI approval overlay proof and Deny/Allow workflow
- Summary: Fork attempted actual SafeGuard TUI workflow verification but did not complete the requested live tmux smoke. It verified controller-mode `human_input.requested` production, current PHAR/container compilation, and Castor QA, and concluded stale PHAR cache likely caused the prior issue. However it did not drive `castor run:agent-test`/tmux to visually prove the approval overlay renders or test Deny/Allow-once end-to-end, so the user-facing smoke remains unresolved. Relaunching with stricter non-interactive tmux automation instructions.
