# flowrite

**Autonomous documentation agents for ZIO libraries, built on [Flue](https://flueframework.com).**

flowrite reads a real ZIO library checkout and writes documentation that actually
compiles: reference pages, module references, tutorials and how-to guides, grounded
in the library's own source, verified with `mdoc`, and integrated into the docs site.

It exists as much as a *demonstration* as a tool. Every non-trivial documentation
task here is handled by an agent whose behavior lives in prose and skills — not in
imperative TypeScript. The point of this README is to show how little code that
takes, and how tight the build → test → observe → fix loop is when you build agents
this way.

---

## Why Flue

An agent is not a program you write step by step. It's a *context you assemble*:

> **agent = model + instructions + tools + skills + subagents + sandbox**

The code is just the wrapper. The writer reads a plain request, decides what kind of document it
is, and then every capability it has is a thing you *hand it*, not a branch you write:

```ts
// src/agent.ts
'use agent';
export function DocsWriter() {
  const [kind] = usePersistentState<DocKind | null>('docKind', null);
  const [subject] = usePersistentState<string | null>('subject', null);
  useRunBasics(initialData, request);         // model + sandbox + run context

  if (kind === null) return classificationGate();  // one turn: which kind, which subject?

  const config = KINDS[kind];                 // the whole per-kind difference, in a table
  return useDocsWriter({
    instructions: config.instructions,        // who it is — a Markdown file
    skills: config.skills,                   // e.g. mdocConventions + structure + checklist
    tools: config.tools,                      // only THIS kind's phase tools, never every kind's
    runDirective: config.directive(subject),
  });
}

// useDocsWriter is a custom hook — it declares the skills, the guarded phase tools, and the seven
// shared roles with useSubagent.
```

Notice what's *not* there: no "step 1 research, step 2 design, step 3 write"
state machine. The agent is given a goal, a capable environment, and a loop. It
finds the path — read → act → observe → correct → repeat. Hardcoded steps are
brittle; they break the moment reality diverges from the script (and with an LLM
in the loop, reality always diverges).

The interesting engineering therefore moves out of `.ts` files and into:

- **instructions** (`src/instructions/*.md`) — who the agent is and how it should behave,
- **skills** (`src/skills/*/SKILL.md`) — expertise loaded on demand (structure
  templates, checklists, `mdoc` conventions, writing-style rules),
- **phase tools** (`src/tools/phases/*.ts`) — a research/write/verify/integrate step, each
  delegating to a specialized role with a `valibot` result schema,
- **roles** (`src/subagents/*`) — generic delegates (researcher, drafter, reviewer…)
  reused across every writer.

## What's in the box

One agent, `docs-writer`, which writes four kinds of document — the four Diátaxis genres:

| Kind | Writes | Lands in |
|------|--------|----------|
| `data-type` | Exhaustive, API-complete reference pages | `docs/reference/` |
| `module` | Module narrative plus per-type coverage, flat or hierarchical | `docs/reference/` |
| `tutorial` | Narrative, pedagogical guides with companion examples | `docs/guides/` |
| `how-to` | Goal-oriented guides: one task, one path, a working result | `docs/guides/` |

The last two share a directory and are told apart only by the reader's intent — an understanding, or
a finished task. That makes classification the run's riskiest step, which is why the gate names the
discriminator explicitly and asks rather than guesses.

Ask for what you want in plain words — the writer works out which kind it is and what the subject
is, and mounts only that kind's phase tools:

```bash
flue run src/agent.ts --id dtr-Chunk \
  -m "Please write reference documentation for the Chunk data type" \
  --data '{"projectPath":"/path/to/checkout"}'
```

`--data` carries only what a sentence cannot express: the checkout path, phases to skip, and the
module layout override. When a request is ambiguous ("write docs for Chunk" — a reference page or a
tutorial?) the writer asks instead of guessing, because guessing spends hours on the wrong document.
Nothing downstream would catch it: a how-to misfiled as a tutorial is reviewed against the tutorial
checklist and reported as a pass.

The agent captures a structured result plus a **run retrospective** in its final
reply.

The `fixtures/tinyoptics/` directory is a small ZIO optics library (Lens, Prism,
Optional) used as the test target — real Scala source with a real `sbt`/`mdoc`
docs build, small enough to iterate on cheaply.

---

## The development workflow

This is the part worth reading. Building a documentation agent doesn't look like
writing a parser and running its test suite. It looks like a *conversation with the
model's behavior*: you shape context, run it against a real repo, read what it
actually did, and feed the surprises back in. Here is the loop, start to finish,
using the reference-page writer as the running example.

### 1. Plan the feature

The reference-page writer started as a plan, not code. The tutorial-writer already
existed, so the question was: how much can be *reused*, and where does a reference
page genuinely differ?

The design decisions were about **context**, not control flow:

- Reference pages are organized by the type's **public API**, not a narrative arc —
  so research needs an API-surface-shaped result schema (every constructor, every
  method with its real signature, every subtype), whereas tutorials use a
  pedagogical schema.
- The generic delegate roles (researcher, drafter, reviewer, …) could be shared
  wholesale; the *document-kind-specific* focus (schema, structure template,
  checklist) gets injected by the phase tools at each delegation call site.
- Every researched fact must carry a **source citation** (`path:L<start>-L<end>`)
  so the drafter can't hallucinate an API that isn't in the source.

That plan is deliberately about *what the agent knows and produces*, never a
prescribed sequence of moves.

### 2. Implement — assemble the context

Implementation is mostly Markdown and schemas:

This is what adding `how-to` as a fourth kind actually cost, in order:

- Write the kind's identity in `src/instructions/<kind>.md` — the flow it drives, the paths it
  writes, the sidebar category it names to the integrator.
- Add two skills: `<kind>-structure` (the section template) and `<kind>-checklist` (what "done"
  means), each a short `SKILL.md` stub over a `references/` file. `mdoc-conventions`,
  `companion-examples` and `writing-style` are reused as-is.
- Add the kind to `DOC_KINDS` in `src/runtime/run-context.ts`, its row to `KINDS`, and its two
  documents to `STRUCTURES` and `CHECKLISTS` in `src/runtime/kind-docs.ts`.

No phase tools, no new module, no schema: thirteen phase tools were deleted in favour of the built-in
`task` tool, so a kind delegates to the same generic roles the others do. `designer` and `drafter`
pick the new template up automatically — both read `structureBlock(docKind())` at their own render.

`tsc` enforces most of that: the two `Record<DocKind, string>` maps and the `KINDS[kind]` index all
fail until the kind is wired. What it does NOT reach is the prose — `GATE_INSTRUCTIONS`, two subagent
descriptions, and the fixture's `AGENTS.md` each enumerated three kinds in text and had to be found
by hand. That asymmetry is the real cost of a new kind, and it is worth knowing before the fifth.

Model choice is centralized in `src/runtime/models.ts` as **tiers**, each
env-overridable per run — so the same agent runs on cheap models under test and
capable ones in production without a code change:

```ts
writer:     { model: WRITER_MODEL     ?? 'anthropic/claude-sonnet-4-6', effort: 'high'   },
researcher: { model: RESEARCHER_MODEL ?? 'anthropic/claude-haiku-4-5',  effort: 'low'    },
reviewer:   { model: REVIEWER_MODEL   ?? 'anthropic/claude-sonnet-4-6', effort: 'low'    },
// …
```

### 3. Test the agent on tinyoptics

`.env.testing` pins every tier to Haiku at `low` effort — the whole loop runs for
cents:

```bash
# .env.testing selects cheap models; --data points at the tinyoptics fixture
flue run src/agent.ts \
  --env .env.testing --id dtr-Prism \
  -m "Please write reference documentation for the Prism data type" \
  --data '{ "projectPath": "fixtures/tinyoptics" }'
```

> If `pnpm exec flue` misbehaves, call the binary directly: `./node_modules/.bin/flue run …`.

The agent then runs the full flow against real Scala:
research → write → verify compliance → method coverage → `mdoc` verify → examples →
format/lint → integrate → review. It's driving `sbt`, reading source, editing
Markdown, and compiling — in a sandbox, on a throwaway checkout, with no human in
the loop.

### 4. Investigate the logs

Every run writes a `flue.log` and finishes with three lines that make the run
*observable by construction*. From an actual tutorial run on `Prism`:

```
info write-tutorial token consumption: 6671373 tokens
     (in 33357, out 88613, cacheRead 6180078, cacheWrite 369325)
     across 248 turns, cost $1.9397
info write-tutorial component usage: [ … per-component call counts, tokens, cost … ]
```

The **component usage** line is the money view — it breaks spend down by subagent,
action, skill, and tool, so you can see exactly where the tokens went:

Some role names below are historical — this is real output from an archived run, and
`style_checker` and `tutorial_drafter` no longer exist (the three writers merged into
one, and the style loop was removed). The shape of the view is the point.

| component | calls | cost |
|-----------|-------|------|
| `docs_integrator` (subagent) | 1 | $0.41 |
| `style_checker` (subagent) | 10 | $0.37 |
| `examples_builder` (subagent) | 1 | $0.34 |
| `tutorial_drafter` (subagent) | 1 | $0.25 |
| `bash` (tool) | 120 | — |
| `read` (tool) | 48 | — |

That table is how the `ARCHITECTURE-REVIEW.md` in this repo was written: it
immediately flagged that some subagents were silently inheriting Sonnet + `high`
thinking for what is really mechanical work — the single biggest cost leak, fixable
by handing them a cheaper tier. Set `FLUE_VERBOSE_TOOLS=1` to also stream every
tool/subagent call with its arguments, result, and duration when you need to see
*what* a step did, not just how much it cost.

### 5. Find issues for the next round of fixes

The workflow doesn't just run the agent — it asks the agent, at the end, for a
**retrospective**: the real obstacles it hit and, crucially, a concrete
`suggestedFix` for each. The result schema forces the shape:

```ts
insights: array({
  phase:        picklist([...]),
  obstacle:     'What actually went wrong or slowed you down this run',
  resolution:   'How you got past it',
  suggestedFix: 'A concrete instruction/tool/schema change to prevent it — or null',
})
```

Real insights from the `Prism` run above:

- **examples phase** — "original tutorial code tried to compose `circleRadiusP` with
  itself (both `Prism[Circle, Double]`); the correct pattern needs nested sum
  types." → *suggestedFix: verify composition type signatures against the examples
  builder's validated output before writing the section.*
- **mdoc phase** — "compile failed on that type mismatch plus a stray `prism-dup.md`
  left in the docs dir." → *suggestedFix: clean up generated files before compiling.*
- **review phase** — "missing audience statement, missing learning objectives,
  code blocks mixing multiple concepts." → *suggestedFix: load the checklist and
  style skills before the write phase so those are planned from the start.*

Each `suggestedFix` is an edit to an **instruction, skill, or schema** — never a new
`if` branch. That closes the loop: the agent tells you how to improve its own
context, you edit a `.md` or a `valibot` schema, and re-run against the fixture.
Old runs are archived under `fixtures/tinyoptics-archive/<run>/flue.log` so you can
diff behavior across iterations of the prompt.

> **Resuming a run.** The tail phases are expensive; the `skipPhases` input lets you
> re-run only the verification/examples/integrate/review tail against artifacts a
> previous run already produced — so fixing a review-phase instruction doesn't cost
> a fresh research pass. Research results are also content-cached under `.cache/`.

---

## Repository layout

```
src/
  agent.ts       # the one agent: classifies the request, then mounts that kind's tools
  app.ts         # HTTP route map — what makes the agent servable
  db.ts          # conversation storage (data/flue.db)
  instructions/  # one identity (.md) per kind of document
  subagents/     # generic delegate roles, shared across every writer
  skills/        # structure templates, checklists, mdoc + writing-style rules
  tools/         # gh query, method-coverage
    phases/      # research / write / verify / integrate steps (+ result schemas)
  runtime/       # composition, model tiers, token/component tracking, caching
fixtures/
  tinyoptics/          # the ZIO optics library used as the test target
  tinyoptics-archive/  # archived flue.log per run, for diffing behavior
```

## Getting started

```bash
pnpm install
cp .env.testing.example .env.testing   # add ANTHROPIC_API_KEY

# run against the bundled fixture (cheap models)
flue run src/agent.ts --env .env.testing \
  --id dtr-Prism \
  -m "Please write reference documentation for the Prism data type" \
  --data '{ "projectPath": "fixtures/tinyoptics" }'
```

`flue run` is how flowrite is actually used — it invokes the agent directly and never
touches `app.ts`. The server build exists for when you want the agent reachable over
HTTP instead:

```bash
pnpm build   # bundles src/app.ts into dist/ (Vite + the flue plugin)
pnpm dev     # the same app on a dev server
```

Flue's own docs ship with the packages — read them directly rather than guessing at
API signatures:

```bash
flue docs                 # list documentation pages
flue docs read <path>     # print a page as Markdown
flue docs search <query>  # search the docs
```

(or browse `node_modules/@flue/{runtime,cli,sdk}/docs`).
