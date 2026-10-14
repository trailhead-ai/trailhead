## A test must execute the thing it tests

A test's subject is a **behaviour**, and the only way to observe a behaviour is to
run the code that produces it. An assertion about the *source* — that a function is
defined, that a config key is set, that a sentence appears in a skill's markdown —
has observed the artifact, not the behaviour. It passes on a codebase where the
thing is present and broken; it fails on a correct rename that changed nothing. It
is a `grep` wearing a green checkmark.

**The rule:** every test runs its subject — calls the function, invokes the CLI,
loads the file through its real loader, dispatches the agent — and asserts on what
came back. **If nothing was executed before the assertion, it is not a test.** It
does not ship, and it does not count as coverage.

### A test needs an input it can vary

Running the subject is the floor, not the bar. A test earns its place by showing
that the subject's answer *depends on what it was given* — feed it one thing, get
one answer; feed it another, get a different one. That dependency is the property
a unit test exists to protect, because it is the property a later edit can break
without noticing.

**The rule:** the subject must have an input that can change its answer, and the
test must be one of the points that changes it. Where a unit has only one possible
output, there is no behaviour to pin — only a decision to restate.

Restating a decision looks like this:

```
assert DEFAULT_SORT == "created_at desc"            # the default sort order
assert set(manifest.skills) == {"pull_request"}     # the shipped inventory
assert render() == GOLDEN                           # a byte-for-byte snapshot
assert SEVERITIES == ("Critical", "Important", "Minor")   # a closed vocabulary
assert "never do X" in skill_md                     # a sentence someone typed
```

Each is true by construction. None can fail for any reason except that a person
changed their mind — at which point the test is not catching a regression, it is
asking them to make the same edit twice. The decision is already recorded in the
code. A test that copies it out adds a second copy to keep in sync, not a check.

The same subjects, tested for behaviour instead, vary the input across the branch
that decides:

- the sort key the caller **asked** for, against the order that comes back
- an inventory built from a manifest with two entries, and one with none
- the renderer at each level it maps, and at a level it must refuse
- a value on either side of the threshold that flips the answer
- the document that satisfies the gate, and the one edit that makes it fail

**How to tell them apart.** Ask what would have to break for this test to go red.
If the honest answer is "someone edits this same constant, or rewords this
sentence", it is guarding a decision. If it is "the logic mapping inputs to
outputs stops working", it is guarding a behaviour. Only the second is coverage.

**The one exception is the seam smoke.** Wiring — the installer really writes the
tree, the documented command really parses, the plugin really loads — has no input
to vary and is still worth exactly one test, because nothing else shows the pieces
are connected. One per seam, never one per constant the seam happens to touch.

`scripts/inert-test-gate` holds both rules mechanically: it flags a test that runs
nothing, and a test whose whole subject is a document it reads and never varies. A
deliberate seam smoke carries `# inert-gate: allow <reason>` on its `def` line, so
the exemptions stay countable and reviewable rather than accumulating unseen.

### The tests worth writing, in the order you should reach for them

1. **The contract, exercised end to end.** Call the public entry point with real
   inputs; assert the returned value, the written file, the exit code, the emitted
   record. This is the default and most tests should be this.
2. **The boundaries that decide something.** Empty, one, many; the edge that flips
   a branch; the value on either side of a threshold. Each one is a separate test
   that fails for exactly one reason.
3. **The failure paths.** Bad input, a missing dependency, an unwritable target, a
   permission denial. Assert the *observable* consequence — the raised type, the
   message a human reads, the state left behind — not that a log line was emitted.
4. **The regression.** A bug you just fixed, pinned by a test that fails against
   the pre-fix code. Nothing else proves the fix was the fix.
5. **The integration seam.** Two components you wired together, run together, with
   the real adapter where it is cheap enough to do so.

Everything else is a nice-to-have. These five are the floor.

### Presence is not behaviour — unless your test produced it

The line is not what the assertion *looks* like. It is whether **the test ran the
code that produced the thing being asserted about.** Existence is a perfectly good
observation when it is the observable output of a step you just executed.

Legitimate — the subject ran, and the file on disk is its result:

```
run_install(env=env)                                   # ← the subject ran
assert (claude_dir / "rules" / "trailhead-craft.md").exists()
```

Banned — nothing ran, and the assertion describes the repo as checked out:

```
assert hasattr(module, "resolve")            # the symbol exists
assert "never do X" in skill_md              # the instruction is written down
assert (repo_root / "config.toml").exists()  # the file was committed
assert isinstance(handler, Callable)         # something callable was defined
```

Each banned form makes the same mistake: it inspects the shape of the source
instead of running it. A function that exists and returns the wrong answer passes
all four, on every commit, forever.

The fix is never to delete the intent — it is to find the consumer and run it. The
symbol exists *so that* a caller can use it: call it and assert the result. The
committed file exists *so that* a loader can read it: load it and assert what the
loader produced. If you cannot name a consumer that would break without the thing,
you have found something with no behaviour to test, and the question is whether it
should exist at all.

**Contents beat existence.** Where a generator, installer, or build step writes
files, existence pins only that the step *ran*; contents pin that it did the *right
thing*. A generator that creates every expected path and fills each with garbage
passes an existence check clean. Assert on what is in the file — or better, on what
the real loader makes of it — whenever the format lets you. Treat a bare existence
assertion as the weakest acceptable form, reached for when the artifact is opaque
or its contents are genuinely not the point, not as the target.

### Absence is not behaviour either

Never write a test whose subject is that something is *gone* — a file does not
exist, a symbol is undefined, a config key is absent, an endpoint 404s because it
was deleted. This is the same error as presence, in the mirror. Removal is not
behaviour, and a test that asserts it is worthless in both directions: it passes
vacuously on a fresh checkout where the thing never existed, and it pins a one-time
migration as a permanent invariant that some future change has to argue its way
past.

Test the behaviour the removal was *for*. If a file was deleted because its loader
now reads from a different source, pin that the loader reads the new source. If an
endpoint was removed because callers moved, pin that the callers work. The absence
is an implementation detail of that outcome, not the outcome.

### Testing a prose artifact — skills, agents, prompts, rulesets

A skill or an agent definition is source, not behaviour, and the temptation to
assert on its text is exactly the trap above. There are only two honest ways to
test one:

- **Run it through its consumer.** The composer, the installer, the manifest
  loader, the front-matter parser. Assert on what the consumer produced — the
  installed path and its contents, the discovered skill list, the parsed
  capability set. This is a real test: something executed.
- **Run the agent against a scenario and judge the outcome.** A behavioral eval
  with a fixture and an expected verdict. Expensive, so reserve it for the
  instructions that actually decide something.

Asserting that a sentence is present in a markdown file tests that someone typed
it. It cannot tell you the agent read it, understood it, or obeyed it — which was
the entire question.

## Test-driven development — required, not preferred

Write the failing test **before** the implementation. Every behaviour change, every
time. This is not a style preference and there is no "too small to test" carve-out
for behaviour.

**Why it is load-bearing.** A test written after the code encodes what the code
*does* rather than what it *should do*, locking in the implementation along with its
bugs. It also passes on its first run, so it has never demonstrated that it *can*
fail — and a test that has never failed is an assertion with no evidence behind it.
A green suite proves nothing about tests that were never red.

### The loop

1. Write the test. Run it. **Confirm it fails, and fails for the stated reason** —
   not on an import error or a typo.
2. Write the minimum implementation that makes it pass.
3. Run the tests covering the change's blast radius — the new test plus the
   file's or module's existing tests, and any suite that exercises a caller of what
   you touched. **Not the whole suite.**

Scoping the run is required, not an optimization. A full-suite run per edit is
minutes of waiting for signal that a targeted run gives in seconds, and it buries
the failure you care about in output about code you did not touch. Name the blast
radius out loud when it is not obvious ("this changes the parser, so parser +
the two importers that call it").

Run the full suite **once**, at the end — before handing work back, opening a PR,
or calling a change done. Not after every red/green cycle. If a targeted run leaves
you unsure what the blast radius actually is, that uncertainty is the reason to go
find out (grep the callers), not the excuse to run everything.

Report the red state before implementing. "I wrote the test and it failed as
expected" is part of the work product, not a formality to skip in the retelling.

### Dispatching implementation work

An executor or subagent given a slice to build is told explicitly to make the test
fail first and to report that failure. A task body carrying a test contract is not
sufficient on its own — say it in the dispatch.

### When the code already exists (repair only)

Writing tests after the fact is legitimate **only** as repair of an already-made
mistake — someone else's untested change, or your own already shipped. It is never
the plan. When repairing:

- Derive the tests from the contract, spec, or intended behaviour. **Never by
  reading the implementation** — that reproduces its bugs as expectations.
- **Mutation-check every test.** Deliberately break the corresponding behaviour,
  confirm the test fails, restore the code exactly, confirm it passes. Verify the
  restore with a diff that must come back empty.
- A mutation that no test catches means the behaviour is unpinned. Strengthen the
  test and re-check; do not move on.
- Name it as repair when reporting. Post-hoc coverage that has passed a mutation
  check is worth having; presenting it as though it were test-first is not.

A mutation check is also the cheapest detector for the failure this ruleset opens
with: a test that never executes its subject cannot be made to fail by breaking
that subject. If the mutation does not turn the test red, the test was not testing
it.

### Never

- Weaken, skip, or delete a test to make a suite green.
- Assert a suite passes without having run it.
- Treat "the tests pass" as evidence when the tests were written after the code and
  never mutation-checked.
- Ship an assertion that never ran the code it names.
- Ship an assertion whose subject has only one possible output — a constant, a
  snapshot, an inventory, a sentence in a document — outside a marked seam smoke.
- Keep a test alive because deleting it would lower a coverage number. A test that
  cannot fail for a real reason is not coverage; it is a maintenance cost that
  reads as safety.
