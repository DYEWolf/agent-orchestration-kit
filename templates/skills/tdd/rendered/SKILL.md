---
name: tdd
description: Test-driven development. Use when the user wants to build features
  or fix bugs test-first, mentions "red-green-refactor", or wants integration
  tests.
---

## Orca execution overlay

The following rules are part of this installed skill and override conflicting
instructions in the upstream body below.

- The coordinator owns the user conversation, GitHub Issue state, Orca Run and
  Task DAG, worktree placement, gates, and final integration decisions.
- A dispatched worker performs only its bounded Task. It does not create Runs,
  Tasks, worktrees, branches, nested agents, or background agents.
- Where the upstream text says to call a Skill tool, invoke a named installed
  skill through the current harness's supported skill discovery. A worker asks
  its coordinator when another Task or skill invocation is required.
- Where the upstream text says to ask or wait for the user, the coordinator uses
  the user conversation; a worker uses the Orca ask/reply flow.
- Where the upstream text says to spawn a subagent, background agent, or parallel
  reviewer, the coordinator creates bounded Orca Tasks and Dispatches. Workers
  never nest delegation.
- Repository mutations such as assignment, Issue updates, commits, staging,
  branching, or conflict continuation happen only when the Task contract assigns
  them to that actor. The CLI itself never commits, pushes, branches, or opens a
  pull request.
- A worker completes its Dispatch exactly once with concrete evidence and stops.
  Review workers report `SHIP`, `FIX_FIRST`, or `RETHINK` and do not implement
  their own corrections.
- GitHub tracker operations follow `docs/agents/issue-tracker.md`. Do not fall
  back to a local Markdown tracker in this installation.

The remaining section is the pinned upstream procedure, adapted only by the
recorded maintainer patch shipped with this snapshot.

## Pinned upstream procedure

# Test-Driven Development

TDD is the red → green loop. This skill is the reference that makes that loop produce tests worth keeping: what a good test is, where tests go, the anti-patterns, and the rules of the loop. Every section applies on every cycle: consult them before and during the loop, not after.

When exploring the codebase, read `CONTEXT.md` (if it exists) so test names and interface vocabulary match the project's domain language, and respect ADRs in the area you're touching.

## What a good test is

Tests verify behavior through public interfaces, not implementation details. Code can change entirely; tests shouldn't. A good test reads like a specification: "user can checkout with valid cart" tells you exactly what capability exists, and it survives refactors because it doesn't care about internal structure.

See [tests.md](tests.md) for examples and [mocking.md](mocking.md) for mocking guidelines.

## Seams: where tests go

A **seam** is the public boundary you test at: the interface where you observe behavior without reaching inside. Tests live at seams, never against internals.

**Test only at pre-agreed seams.** Before writing any test, write down the seams under test and confirm them with the user. No test is written at an unconfirmed seam. You can't test everything, so agreeing the seams up front is how testing effort lands on the critical paths and complex logic instead of every edge case.

Ask: "What's the public interface, and which seams should we test?"

When the shape of that interface is itself in question (how deep the module is, where the seam belongs, what the interface should expose), call the Skill tool with "codebase-design" for the vocabulary. It is the shared source of the module, interface, depth, seam, adapter, leverage and locality terms, and it is a reference to consult, not a session to run.

## Anti-patterns

- **Implementation-coupled**: mocks internal collaborators, tests private methods, or verifies through a side channel (querying the database instead of using the interface). The tell: the test breaks when you refactor but behavior hasn't changed.
- **Tautological**: the assertion recomputes the expected value the way the code does (`expect(add(a, b)).toBe(a + b)`, a snapshot derived by hand the same way, a constant asserted equal to itself), so it passes by construction and can never disagree with the code. Expected values must come from an independent source of truth: a known-good literal, a worked example, the spec.
- **Horizontal slicing**: writing all tests first, then all implementation. Bulk tests verify _imagined_ behavior: you test the _shape_ of things rather than user-facing behavior, the tests go insensitive to real changes, and you commit to test structure before understanding the implementation. Work in **vertical slices** instead: one test → one implementation → repeat, each test a **tracer bullet** that responds to what the last cycle taught you.

## Rules of the loop

- **Red before green.** Write the failing test first, then only enough code to pass it. Don't anticipate future tests or add speculative features.
- **One slice at a time.** One seam, one test, one minimal implementation per cycle.
- **Refactoring is not part of the loop.** It belongs to the review stage (see the `code-review` skill), not the red → green implementation cycle.
