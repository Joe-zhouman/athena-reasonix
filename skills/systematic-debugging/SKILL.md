---
name: systematic-debugging
description: Use when you can reproduce a bug but don't know the root cause — a failing test exists or can be written, and you need systematic analysis before touching code. NOT for bugs with no clear repro (use diagnosing-bugs); NOT for bugs you already understand and just need to fix (dispatch cancer directly)
---

# Systematic Debugging

## Overview

Random fixes waste time and create new bugs. Quick patches mask underlying issues.

**Core principle:** ALWAYS find root cause before attempting fixes. Symptom fixes are failure.

**Violating the letter of this process is violating the spirit of debugging.**

## The Iron Law

```
NO FIXES WITHOUT ROOT CAUSE INVESTIGATION FIRST
```

If you haven't completed Phase 1, you cannot propose fixes.

**Why:** A symptom is what the bug *does*; the root cause is what the bug *is*. Patching the symptom is betting the bug has no other effects — but by definition you haven't checked, because checking *is* root-cause investigation. Symptom patches "work" in the sense that the one observed failure goes away, while silently leaving the actual fault in place to surface again elsewhere, often as a worse bug you no longer connect to this one. The fix that feels slow (investigate first) is the only one that doesn't guarantee rework.

## When to Use

Use for ANY technical issue:
- Test failures
- Bugs in production
- Unexpected behavior
- Performance problems
- Build failures
- Integration issues

**Use this ESPECIALLY when:**
- Under time pressure (emergencies make guessing tempting)
- "Just one quick fix" seems obvious
- You've already tried multiple fixes
- Previous fix didn't work
- You don't fully understand the issue

**Don't skip when:**
- Issue seems simple (simple bugs have root causes too)
- You're in a hurry (rushing guarantees rework)
- Manager wants it fixed NOW (systematic is faster than thrashing)

## The Four Phases

You MUST complete each phase before proceeding to the next.

### Phase 1: Root Cause Investigation

**BEFORE attempting ANY fix:**

1. **Read Error Messages Carefully**
   - Don't skip past errors or warnings
   - They often contain the exact solution
   - Read stack traces completely
   - Note line numbers, file paths, error codes

2. **Reproduce Consistently**
   - Can you trigger it reliably?
   - What are the exact steps?
   - Does it happen every time?
   - If not reproducible → gather more data, don't guess

   **Why "don't guess when not reproducible":** a fix you can't verify is a fix you can't know worked. If the bug is intermittent, the "fix" will appear to work simply because the bug didn't happen to recur — and you'll move on while the real cause is still there. The discipline is: no reproduction, no fix. Keep gathering evidence (logs, frequency, triggers) until you can make it happen on demand. A reproducible bug is a solved bug; an irreproducible "fix" is a hope.

3. **Check Recent Changes**
   - What changed that could cause this?
   - Git diff, recent commits
   - New dependencies, config changes
   - Environmental differences

4. **Gather Evidence in Multi-Component Systems**

   **WHEN system has multiple components (CI → build → signing, API → service → database):**

   **BEFORE proposing fixes, add diagnostic instrumentation:**
   ```
   For EACH component boundary:
     - Log what data enters component
     - Log what data exits component
     - Verify environment/config propagation
     - Check state at each layer

   Run once to gather evidence showing WHERE it breaks
   THEN analyze evidence to identify failing component
   THEN investigate that specific component
   ```

   **Example (multi-layer system):**
   ```bash
   # Layer 1: Workflow
   echo "=== Secrets available in workflow: ==="
   echo "IDENTITY: ${IDENTITY:+SET}${IDENTITY:-UNSET}"

   # Layer 2: Build script
   echo "=== Env vars in build script: ==="
   env | grep IDENTITY || echo "IDENTITY not in environment"

   # Layer 3: Signing script
   echo "=== Keychain state: ==="
   security list-keychains
   security find-identity -v

   # Layer 4: Actual signing
   codesign --sign "$IDENTITY" --verbose=4 "$APP"
   ```

   **This reveals:** Which layer fails (secrets → workflow ✓, workflow → build ✗)

5. **Trace Data Flow**

   **WHEN error is deep in call stack:**

   See `root-cause-tracing.md` in this directory for the complete backward tracing technique.

   **Quick version:**
   - Where does bad value originate?
   - What called this with bad value?
   - Keep tracing up until you find the source
   - Fix at source, not at symptom

### Phase 2: Pattern Analysis

**Find the pattern before fixing:**

1. **Find Working Examples**
   - Locate similar working code in same codebase
   - What works that's similar to what's broken?

2. **Compare Against References**
   - If implementing pattern, read reference implementation COMPLETELY
   - Don't skim - read every line
   - Understand the pattern fully before applying

3. **Identify Differences**
   - What's different between working and broken?
   - List every difference, however small
   - Don't assume "that can't matter"

4. **Understand Dependencies**
   - What other components does this need?
   - What settings, config, environment?
   - What assumptions does it make?

### Phase 3: Hypothesis and Testing

**Scientific method:**

1. **Form Single Hypothesis**
   - State clearly: "I think X is the root cause because Y"
   - Write it down
   - Be specific, not vague

2. **Test Minimally**
   - Make the SMALLEST possible change to test hypothesis
   - One variable at a time
   - Don't fix multiple things at once

   **Why "one variable at a time":** if you change three things and the bug disappears, you don't know which change fixed it — and worse, one of the other two changes may have introduced a *new* bug that's currently masked by the fix working. You're left with a working system and no model of why, which means the next similar bug you can't reason about. One change → observe → reason. That's the only way each step adds to your understanding instead of muddying it.

3. **Verify Before Continuing**
   - Did it work? Yes → Phase 4
   - Didn't work? Form NEW hypothesis
   - DON'T add more fixes on top

4. **When You Don't Know**
   - Say "I don't understand X"
   - Don't pretend to know
   - Ask for help
   - Research more

### Phase 4: Implementation

**Fix the root cause, not the symptom:**

1. **Create Failing Test Case**
   - Simplest possible reproduction
   - Automated test if possible
   - One-off test script if no framework
   - MUST have before fixing
   - Use the `superpowers:test-driven-development` skill for writing proper failing tests

2. **Implement Single Fix**
   - Address the root cause identified
   - ONE change at a time
   - No "while I'm here" improvements
   - No bundled refactoring

   **Why no "while I'm here":** a debugging commit must say "this changed because the bug was X." Bundling a refactor or improvement into the same change ties an unreviewed modification to a fix that *had* to ship. If the bundled change later causes a regression, you can't revert the fix without losing the refactor — and you can't reason about which change caused the new bug because they landed together. Debugging commits are surgical on purpose: one fault in, one fix out, nothing else moves.

3. **Verify Fix**
   - Test passes now?
   - No other tests broken?
   - Issue actually resolved?

4. **If Fix Doesn't Work**
   - STOP
   - Count: How many fixes have you tried?
   - If < 3: Return to Phase 1, re-analyze with new information
   - **If ≥ 3: STOP and question the architecture (step 5 below)**
   - DON'T attempt Fix #4 without architectural discussion

5. **If 3+ Fixes Failed: Question Architecture**

   **Why this is the rule, not "try harder":** each failed fix is evidence — not about the bug, but about the *shape* of the problem. When three different fixes each reveal a *new* problem in a *different* place, the common cause is no longer inside any one component: it's the architecture that connects them. A fourth fix at that point isn't perseverance, it's the sunk-cost fallacy — you're patching a structure whose assumptions are wrong, and every patch just moves the stress to the next weak joint. The disciplined move is counter-intuitive: stop fixing, start doubting the design. That's not giving up — it's recognizing that the bug is telling you the architecture is the bug.

   **Pattern indicating architectural problem:**
   - Each fix reveals new shared state/coupling/problem in different place
   - Fixes require "massive refactoring" to implement
   - Each fix creates new symptoms elsewhere

   **STOP and question fundamentals:**
   - Is this pattern fundamentally sound?
   - Are we "sticking with it through sheer inertia"?
   - Should we refactor architecture vs. continue fixing symptoms?

   **Discuss with your human partner before attempting more fixes**

   This is NOT a failed hypothesis - this is a wrong architecture.

## Red Flags - STOP and Follow Process

If you catch yourself thinking:
- "Quick fix for now, investigate later"
- "Just try changing X and see if it works"
- "Add multiple changes, run tests"
- "Skip the test, I'll manually verify"
- "It's probably X, let me fix that"
- "I don't fully understand but this might work"
- "Pattern says X but I'll adapt it differently"
- "Here are the main problems: [lists fixes without investigation]"
- Proposing solutions before tracing data flow
- **"One more fix attempt" (when already tried 2+)**
- **Each fix reveals new problem in different place**

**ALL of these mean: STOP. Return to Phase 1.**

**If 3+ fixes failed:** Question the architecture (see Phase 4.5)

## your human partner's Signals You're Doing It Wrong

**Watch for these redirections:**
- "Is that not happening?" - You assumed without verifying
- "Will it show us...?" - You should have added evidence gathering
- "Stop guessing" - You're proposing fixes without understanding
- "Ultrathink this" - Question fundamentals, not just symptoms
- "We're stuck?" (frustrated) - Your approach isn't working

**When you see these:** STOP. Return to Phase 1.

## Common Rationalizations

| Excuse | Reality | Why |
|--------|---------|-----|
| "Issue is simple, don't need process" | Simple issues have root causes too. Process is fast for simple bugs. | "Simple" is your estimate before investigating — exactly the moment you have the least information. Simple bugs *that you understand* may not need much process, but you only know you understand it *after* the process confirms the cause. Skipping the process on a "simple" bug means betting your pre-investigation guess was right, when the process to check is minutes. |
| "Emergency, no time for process" | Systematic debugging is FASTER than guess-and-check thrashing. | Guess-and-check feels fast because each guess is quick — but the failure mode is you try 5 guesses, each "almost works," and burn an hour. Systematic is slower per step but converges, because each step narrows the cause instead of adding new variables. Under time pressure, the slow-converging path is the only one that actually ends. |
| "Just try this first, then investigate" | First fix sets the pattern. Do it right from the start. | The first fix you attempt becomes your working theory of the bug — if it's a guess, you've now anchored on a guess, and your subsequent investigation will be biased toward confirming it. Doing the investigation first means your first fix is informed, not anchoring. |
| "I'll write test after confirming fix works" | Untested fixes don't stick. Test first proves it. | If you fix first and it "works," you have no test proving the bug existed or that the fix addresses it — so when a later change reintroduces the bug, nothing catches it and you have no record of what the fix was for. The failing test *is* the proof the bug existed and the fix is real; writing it after is how regressions silently return. |
| "Multiple fixes at once saves time" | Can't isolate what worked. Causes new bugs. | Parallel changes can't be attributed: if the bug goes away, you don't know which change did it, and the other changes are now unreviewed modifications riding along. If a new bug appears next week, you can't tell which of the bundled changes caused it. "Saves time now" costs you the ability to reason about your own system later. |
| "Reference too long, I'll adapt the pattern" | Partial understanding guarantees bugs. Read it completely. | A pattern's correctness usually lives in the parts that *look* optional — the edge-case handling, the ordering, the error paths you skimmed past. Adapting from a partial read means copying the shape without the load-bearing details, and the bugs it introduces are exactly in the parts you didn't read. |
| "I see the problem, let me fix it" | Seeing symptoms ≠ understanding root cause. | "I see it" is a description of the symptom (what breaks), not the cause (why it breaks). Fixing at the symptom level is the Iron Law violation — the cause is still there. You haven't seen the problem until you can explain the mechanism that produces the symptom, not just point at the symptom. |
| "One more fix attempt" (after 2+ failures) | 3+ failures = architectural problem. Question pattern, don't fix again. | Each failed fix is data about the problem's shape, not just about the bug. Three fixes failing in different places is strong evidence the fault is structural, not local — and a fourth local fix will fail for the same structural reason. The impulse to "try once more" is sunk cost, not insight; the architecture is telling you it's the architecture. |

## Quick Reference

| Phase | Key Activities | Success Criteria |
|-------|---------------|------------------|
| **1. Root Cause** | Read errors, reproduce, check changes, gather evidence | Understand WHAT and WHY |
| **2. Pattern** | Find working examples, compare | Identify differences |
| **3. Hypothesis** | Form theory, test minimally | Confirmed or new hypothesis |
| **4. Implementation** | Create test, fix, verify | Bug resolved, tests pass |

## When Process Reveals "No Root Cause"

If systematic investigation reveals issue is truly environmental, timing-dependent, or external:

1. You've completed the process
2. Document what you investigated
3. Implement appropriate handling (retry, timeout, error message)
4. Add monitoring/logging for future investigation

**But:** 95% of "no root cause" cases are incomplete investigation.

## Supporting Techniques

These techniques are part of systematic debugging and available in this directory:

- **`root-cause-tracing.md`** - Trace bugs backward through call stack to find original trigger
- **`defense-in-depth.md`** - Add validation at multiple layers after finding root cause
- **`condition-based-waiting.md`** - Replace arbitrary timeouts with condition polling

**Related skills:**
- **superpowers:test-driven-development** - For creating failing test case (Phase 4, Step 1)
- **superpowers:verification-before-completion** - Verify fix worked before claiming success

## Real-World Impact

From debugging sessions:
- Systematic approach: 15-30 minutes to fix
- Random fixes approach: 2-3 hours of thrashing
- First-time fix rate: 95% vs 40%
- New bugs introduced: Near zero vs common
