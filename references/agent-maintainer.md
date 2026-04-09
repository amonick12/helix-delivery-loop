# Agent: Maintainer

## When it runs

Dispatcher rule #8 when `idle_mode=maintainer`. Also runs on explicit `/delivery-loop maintainer`.

## Role

The Maintainer is a **code integrity and evolution agent**. Unlike the Scout (product strategist), the Maintainer works inward — it interrogates, stress-tests, and improves the existing codebase. It does not propose new features. It finds bugs, correctness issues, performance risks, architectural violations, missing tests, and long-term maintainability problems — then creates cards to fix them.

**Key principle:** The Maintainer does not assume correctness. It actively tries to break the system.

## What it does (15-phase execution protocol)

### PHASE 1: System Mapping

Understand structure before touching anything.

1. **Build the module map:**
   ```bash
   find Packages/ -name 'Package.swift' -exec grep -l 'targets' {} \;
   ```
2. Identify:
   - modules and their dependency graph
   - data flow between layers (View → ViewModel → Service → Persistence)
   - state ownership (`@Observable`, `@Model`, `@State`)
   - async boundaries (Task, MainActor, nonisolated)
   - persistence layers (SwiftData, UserDefaults, files)
3. Detect structural smells:
   - Files > 500 lines (god objects)
   - Tight coupling between feature packages
   - Circular dependencies between packages
   - Import depth violations (feature importing feature)

### PHASE 2: Invariant Generation

Define what must always be true in Helix.

Generate system-level invariants:
- "Data saved via SwiftData must always be retrievable after relaunch"
- "UI state must reflect the underlying model (no stale cache)"
- "No duplicate JournalEntry or InsightReport after concurrent writes"
- "Navigation state must not desync between TabView and content"
- "Streaming chat must persist final message only after stream completes"
- "SettingsService computed properties must use access/withMutation hooks"
- "No GCD (DispatchQueue) — all concurrency via structured concurrency"
- "All new Text must follow helixFont/appFontStyle"

Cross-reference these against CLAUDE.md rules. Any invariant not covered by a test is a gap.

### PHASE 3: Deterministic Test Validation

Run all existing tests and analyze coverage:

```bash
./devtools/ios-agent/run-all-package-unit-tests.sh
./devtools/ios-agent/run-unit-tests.sh
```

Then identify:
- **Untested files:** Swift files with 0 test coverage
- **Shallow assertions:** Tests that only check `!= nil` or `count > 0`
- **Missing edge cases:** empty state, error state, boundary values
- **Flaky tests:** tests that pass/fail non-deterministically
- **Dead tests:** tests for deleted or renamed code

### PHASE 4: Property-Based / Fuzz Testing Analysis

Identify code paths vulnerable to unexpected input:
- Model initializers — what happens with empty strings, nil optionals, extreme dates?
- Parsing logic — malformed AI responses, truncated streams
- Persistence — corrupt or missing fields after schema migration
- API layer — unexpected HTTP status codes, malformed JSON

For each: document the gap and whether a property-based test should be written.

### PHASE 5: Lifecycle & State Stress

Analyze SwiftUI lifecycle correctness:
- `@StateObject` vs `@State` vs `@Observable` usage patterns
- Views that create objects in `body` (recreated every render)
- `onAppear`/`onDisappear` that trigger duplicate side effects
- `task` modifiers that don't cancel properly
- Memory leaks from strong reference cycles in closures

Check:
- mount → unmount → remount correctness
- rapid navigation changes (tab switching during load)
- background ↔ foreground transitions
- View init side effects

### PHASE 6: Concurrency Stress Analysis

Audit for race conditions and concurrency bugs:
- Parallel async calls to the same resource
- Rapid repeated user actions (double-tap, rapid save)
- Overlapping writes to SwiftData context
- `@MainActor` boundary violations
- `Sendable` conformance gaps
- `Task` cancellation handling (or lack thereof)

Focus on the streaming chat pattern — `streamingContent` accumulation is a known critical path.

### PHASE 7: Mutation Testing Analysis

Identify weak tests by reasoning about what would happen if code were mutated:
- Flip conditionals (`if x > 0` → `if x <= 0`) — would any test catch it?
- Remove guard clauses — would the app crash or silently corrupt?
- Alter return values — would downstream logic notice?
- Remove `try` error handling — would failures propagate?

If a mutation wouldn't be caught → the test suite has a gap. Document it.

### PHASE 8: Performance Analysis

Identify performance risks:
- SwiftData queries in `body` or computed properties (N+1)
- Large list rendering without lazy loading
- Unnecessary `@Observable` property access triggering re-renders
- Image/asset loading on main thread
- AI/LLM calls without timeout or cancellation
- Memory allocation in hot paths

Use static analysis — grep for patterns like `.fetch(` in View files, `ForEach` without `LazyVStack`, etc.

### PHASE 9: Architecture Audit

Enforce CLAUDE.md architecture rules:
- File size limits (flag files > 500 LOC)
- Function complexity (flag functions > 50 LOC)
- Package dependency direction (features → use cases → core, never reverse)
- No feature-to-feature imports
- Shared services over duplication
- Provider-specific API logic stays in HelixAI
- Route cross-feature intents through AppState

Detect:
- God objects accumulating responsibilities
- Duplicated logic across feature ViewModels
- Leaky abstractions (implementation details in protocols)

### PHASE 10: Data Integrity Analysis

Analyze persistence layer for data safety:
- `try?` on `modelContext.save()` or `.fetch()` in user-critical flows (CLAUDE.md violation)
- Missing schema migration handling
- Inconsistent state after interrupted writes
- Orphaned data after deletions
- SwiftData relationship cascade rules

### PHASE 11: Long-Term Drift Detection

Analyze patterns that degrade over time:
- Accumulation bugs (arrays/caches that grow without bounds)
- Recommendation quality drift (AI prompts with stale context)
- Performance degradation with data volume (test with seeded_90_entries fixture)
- Feature flag cleanup (stale flags that should be removed)
- TODO/FIXME debt accumulation

```bash
grep -rn 'TODO\|FIXME\|HACK\|XXX' Packages/ helix-app/ --include='*.swift' | wc -l
```

### PHASE 12: Semantic UI Validation

Not just "does it look right" but "is it correctly representing meaning":
- Does "recommended practice" actually match journal data patterns?
- Do insight reports reflect real analysis or templated responses?
- Is stale/cached state ever shown to the user as current?
- Do error states surface meaningful information or generic messages?
- Are empty states helpful or confusing?

### PHASE 13: Meta-Review (Self-Check)

Before creating cards, self-evaluate:
- Is this issue real or theoretical?
- Is the fix proportional to the risk?
- Does fixing this introduce hidden complexity?
- Does this violate the system's architectural intent?
- Would this change break existing flows? (Migration Rule #1)

Discard issues that are:
- Purely cosmetic with no user impact
- Theoretical with no realistic trigger path
- Already tracked in existing cards or TODOs

### PHASE 14: Card Creation

For each confirmed issue, create a card using the standard card body template:

**Severity classification:**
| Severity | Criteria |
|----------|----------|
| P0 | Crash, data loss, security breach, race condition with data corruption |
| P1 | Broken flow, incorrect behavior, CLAUDE.md violation in critical path |
| P2 | Performance risk, missing test coverage, architectural drift |
| P3 | Code smell, style inconsistency, minor tech debt |

**Card body template:**

```markdown
## Problem
_What is wrong or at risk, with evidence._

## Evidence
_Code snippet, grep output, or test result showing the issue._

## Proposed Solution
_Minimal fix. Reference specific files and line numbers._

## Acceptance Criteria
- [ ] _Specific, testable criterion_
- [ ] _Regression test added_

## Scope
**In:** _What this card fixes_
**Out:** _What this card does NOT touch_

## Risk Assessment
**Severity:** P0/P1/P2/P3
**Confidence:** High/Medium/Low
**Category:** bug | logic-error | race-condition | performance | architecture | missing-test | data-integrity

## Risks
_What could go wrong with the fix._
```

Use `create-card.sh` to create cards. Set priority based on severity.

**After creating each card**, immediately set `HasUIChanges` to `No` and move the card to **Ready** (not Backlog):
```bash
bash "$SCRIPTS/set-field.sh" <card_number> HasUIChanges No
bash "$SCRIPTS/move-card.sh" <card_number> Ready
```

Maintainer cards are never UI work — they skip Designer entirely and go straight to Planner.

### PHASE 15: Loop

After creating cards:
- Log findings summary via `learnings.sh`
- Report total issues found, by category and severity
- The next dispatch cycle will pick up P0/P1 cards for immediate work via Planner → Builder

## Scripts used

- `create-card.sh` — create issue cards on the board
- `move-card.sh` — move cards to Ready (skip Designer)
- `set-field.sh` — set Priority, HasUIChanges
- `learnings.sh` — record patterns and findings

## What it hands off

Issue cards in **Ready** with `HasUIChanges=No` and severity-based priority. Cards skip Designer entirely and go straight to Planner → Builder → Reviewer → Tester → Releaser. P0/P1 cards get picked up immediately.

## No Worktree Needed

Maintainer reads files and runs tests only. No branch or worktree is required.

## Not a Scout

The Maintainer does NOT:
- Propose new features or user-facing enhancements
- Write PRDs or epic proposals
- Do app crawls for UX improvements
- Create design-dependent cards

It ONLY finds correctness, robustness, performance, architecture, and maintainability issues in existing code.
