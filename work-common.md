# common rules

Three files run a program. The **setup file** (`zdc-setup.md`) holds what is
specific to this program: paths, pins, datasets, metrics, budgets, the
variables below. The **loop file** (`zdc-autoresearch-loop-v3.md`) holds the
phases: each phase's task, its ruler (what "correct" means in that phase),
its Step 0, its done criterion and extra decision-table rows. This file holds
the rules of every run: the environment, the work protocol, the FIX / DECIDE /
ASK / PARK / STOP protocol, where each kind of fact is stored (memory), and
the documentation, coding and git rules. Every start line reads the setup
file, then this file, then the loop file. Each rule is written once, in the
file that owns it; the other files point to it by section name. Every number
that belongs to this program lives in the setup file, never here or in the
loop file.

## Variables set by the setup file

The setup file sets these in its section Names. Every rule below refers to them.

| variable | meaning | default when the setup file is silent |
|---|---|---|
| `{repo}` | the code tree the program works on: this repository, submodules included | the repository that contains the setup file |
| `{space}` | the folder for all notes, questions, decisions, plots and reports of this program | `{repo}/space` |
| `{ledger}` | the phase ledger: one file per program, append-only, each phase's spec written BEFORE the work starts and its outcome appended at the end | `{space}/LEDGER.md` |
| `{data}` | the root of input data and large outputs, never in git | `/data/zdc-autoresearch` |
| `{scratch}` | temporary files and caches | the scratch folder Claude Code reports |
| `{memory}` | your persistent agent-memory directory, the one that holds `MEMORY.md` | the path the harness reports at session start |
| `{git}` | `off` or `on`: whether you may commit (Git section) | `off` |
| `{online}` | `yes` when the user reads the chat and answers during the run | `no` |

The setup file may add variables of its own (a farm path, an image tag). It
never redefines what the ones above mean.

## Terms

- **Program** — one setup file, one loop file, one `{ledger}`, one `{space}`.
  It spans phases.
- **Phase** — one entry of the ledger: a task with a Step 0, a ruler and a
  done criterion. A phase takes one or several runs. 
  Usually results of a phase are checked by a human before continuation
- **Run** — one autonomous invocation of you on the plan. It starts with the
  start protocol (read STATUS.md, process QUESTIONS.md) and ends in one of
  four ways:
  1. the phase's done criterion is met and the report is written;
  2. a STOP;
  3. nothing can be done — `still waiting on Q<N>`;
  4. an external cut: rate limit, context exhaustion, container stop, the
     user interrupting.
  Ends 1—3 are yours and run the feedback sweep. End 4 is not, and you
  never see it coming — which is why STATUS.md, the ledger and the notes
  are kept current at all times instead of at the end.
- **Session** — the harness's conversation window. A run may span several
  context compactions inside one session; what survives a compaction is
  what is on disk.

## Environment

- You run on the user's machine in Claude Code auto mode, or inside the
  autonomous container the setup file names; the setup file says which. EIC
  software (npsim, eicrecon, ROOT) runs inside the pinned `eic_xl` image
  through the container wrapper script the setup file names; on the farm
  through the ifarm skills. You never install EIC software on the host.
- YOU ARE NOT ALLOWED TO DO ANY CHANGES IN GIT. No commits, no pushes. But
  allowed to read, checkout, compare as needed. The setup file may grant
  commits explicitly (`{git}` = `on`); the Git section then applies.
- Writing: write only under `{repo}`, `{space}`, `{data}`, `{scratch}`,
  `{memory}` and the farm paths the setup file names. Everything else on the
  machine is off limits. The frozen list (`{space}/FROZEN`, enforced by the
  hook `.claude/hooks/protect.py`) narrows this further after Phase 0.
- The system: change nothing on it — no package manager, no `sudo`, no
  services. Python runs through **uv** inside `{repo}` (`uv run`); add
  packages with uv as needed (no typer; plain argparse). A missing tool gets
  its exact install command in `{space}/notes/ENVIRONMENT.md` and one line to
  the user.
- Check the core count (`nproc`) and use it (parallel jobs), keep ~2 cores
  headroom. The headroom rule applies to build and analysis jobs — a timed
  benchmark cell may use every core its protocol calls for, with nothing
  else running beside it.
- The shell: tool calls sent together share one shell and can change each
  other's working folder. Use full paths in every command, redirects
  included. Change folder only inside parentheses: `( cd <folder> && ... )`.

## How you work

- On start: read {space}/STATUS.md if it exists, then process
  {space}/QUESTIONS.md as the FIX / ASK / PARK / STOP section describes —
  both before any other action. Then resume from where the last run
  stopped instead of restarting. If QUESTIONS.md does not exist yet, there
  are no questions — continue.
- STATUS.md is the resume entrypoint. Its shape and size are fixed in the
  Memory section: a `## LIVE` block, a `## RESUME` block, what waits on the
  user, pointers — under ~40 lines, never a journal.
- Write the `## LIVE` block the MOMENT any background job, slurm array, GPU
  allocation or monitor starts or ends — not at session end. Then a mid-run
  death costs nothing and context compaction needs no steering.
- When you create code, make it easy for humans to use and maintain:
  anywhere someone starts reading, the context is quickly clear.
- When you have enough information to act, act. Do not re-litigate decisions
  already made. If weighing a choice about a tool, a threshold, a rule, a
  budget, naming or code, pick one and record it as a `D-default` decision
  (DECIDE). This never overrides FIX / ASK / PARK / STOP: a doubt about the
  user's wishes, the physics goal or a frozen item stays a question.
- The user's time is the scarce resource. Only what the user alone knows
  reaches the user as a question: the goal, the physics, the scope, which
  dataset counts, a frozen item. Everything else is yours to decide and
  record, where the user can veto it.
- Store one lesson per file in {space}/notes/ with a one-line summary
  at the top; update rather than duplicate; delete notes that turn out wrong.
  A lesson's rule changes the config or script that caused the trap in the
  same step, and the lesson names that edit (try 1 wrote the disk lesson and
  left the cause in the config template).
  A lesson that generalizes beyond this program is promoted the same day
  (Memory section).
- Put plots in {space}/plots/phase{#}/ and write results up in
  {space}/reports/phase{#}_.... Previous results, plots and knowledge must
  persist as you progress. Every plot is a PNG; a tool that writes PDF gets
  a PNG beside it (the setup file, Review delivery, names the converter).
- Every timestamp you write into the ledger, the run log, DECISIONS.md or
  QUESTIONS.md comes from `date -u` in the command that writes the entry,
  never from your own sense of time (try 1 wrote some early timestamps ahead
  of the clock).
- A headline number (a report line, a chat line, a deck number) comes from a
  script's output file, never from arithmetic in chat; the setup file names
  the script.
- Record every decision that constrains later work in
  {space}/notes/DECISIONS.md (format in the Memory section). Tie decisions
  to evidence and measured numbers; the numbers themselves stay in the
  reports.
- You are operating autonomously; the user cannot answer questions mid-run.
  For reversible actions that follow from the phase file, proceed. When
  anything unexpected happens — or you catch yourself about to assume
  something the user could have specified — use the FIX / ASK / PARK /
  STOP protocol. Never pursue a doubtful assumption silently.
- Write every question into {space}/QUESTIONS.md the moment it occurs to
  you. That file is your only channel to the user, and it carries every
  kind of question — the ones that block you and the ones that do not.
- Token thrift: you run on a limited LLM budget, so be economical with your
  own effort — compute is cheap, tokens are expensive:
  - Never load raw data into your context. Write scripts that print small
    samples, stats, and summaries; read those instead.
  - Redirect ALL build and run stdout/stderr to log files; inspect them only
    via tail/grep.
  - Run long jobs detached (nohup, background) and poll their logs; never
    block a tool call on a long run. Loop over parameters INSIDE scripts,
    never one tool call per point.
  - Prefer one well-prepared production over many small iterations. CPU
    hours cost nothing from your budget; thinking loops and subagents do.
  - Validate from printed numbers (counts, hashes, MB/s); look at a
    rendered plot at most once per milestone.
  - Do not re-read files you just wrote; re-read only the region you are
    editing.
  - Milestone-first: each phase file names its Step 0; finish and record it
    before any other work. A finished verified milestone is worth more than
    three half-finished ones.
  - Before any open-ended search, state in your notes what you expect to
    find and why. If you can't, put it in the report as "recommended next
    step" instead of doing it.
  - Assume you can be interrupted at any moment (rate limits): keep scripts,
    notes, and partial results on disk at all times so a future run resumes
    rather than restarts; update STATUS.md as you go.

## Memory — where each fact lives

You have no memory between sessions: when a run ends or its context fills,
everything not written to a file is gone. Two layers of files carry the
state, and every fact has exactly ONE canonical home. Everything else
points at that home. When a fact changes, one file changes.

### Layer 1 — project files in {space} (episodic: what happened, in order, with numbers)

| file | holds | rule |
|---|---|---|
| `STATUS.md` | the resume entrypoint | under ~40 lines; structure below; never a journal |
| `{ledger}` | each phase's spec, written before the work starts, and its outcome, appended when it ends | append-only; a dying run leaves its own instructions here |
| `notes/runlog.md` | run history: what was tried, when, with what result | append-only; the reports are authoritative where numbers disagree; never rewrite it |
| `notes/DECISIONS.md` | every decision that constrains later work | one entry per decision: `D-user-<n> (<date>, user, Q<N>): <sentence, the user's words quoted>` for the user's, `D-default-<n> (<date>, agent, phase <N>): <sentence>` for a default you took (DECIDE); each names the evidence it rests on; edit the entry when the decision changes instead of adding a second one; a veto becomes a `D-user` entry that the default's entry then names |
| `notes/lesson-*.md` | one trap per file: what bit, why, the rule that avoids it | one-line summary at the top; update, never duplicate; delete when wrong |
| `notes/ENVIRONMENT.md` | packages and setup a future run must install | |
| `QUESTIONS.md` | every question to the user, in the protocol format | the only channel to the user |
| `reports/phase{#}_*.md` | the scientific record: measured numbers, plots, verdicts | numbers live here and only here |

`STATUS.md` structure, top to bottom:

```markdown
PHASE<N> <state> — one line: the active phase and where it stands
## LIVE
- <every running job, slurm array, GPU allocation, monitor — or "nothing running">
## RESUME
- <what just finished, what to do next, which files to open>
## Waiting on the user
- Q<N> …
## Pointers
- ledger {ledger}; history notes/runlog.md; decisions notes/DECISIONS.md
```

Run history is not STATUS.md's job: it goes to `notes/runlog.md` and the
ledger. When STATUS.md grows past ~40 lines, move the overflow to
`notes/runlog.md` verbatim.

### Layer 2 — agent memory in {memory} (semantic: stable facts, rules, gotchas, pointers)

This directory survives sessions and container rebuilds. It holds one file
per durable fact, plus `MEMORY.md`, the index — the ONLY file loaded into
every new session. Memory files are read on demand, so the index must let
you decide in one glance whether to open one.

A memory file:

```markdown
---
name: short-kebab-case-slug
description: one-line summary, used to decide relevance at recall
metadata:
  node_type: memory
  type: user | feedback | project | reference
---
<the fact; related memories linked as [[other-slug]]>
```

`user` = who the user is (role, expertise, preferences). `feedback` =
corrections and confirmed approaches the user gave: the trigger quoted,
why, how to apply. `project` = ongoing work state not derivable from the
code. `reference` = pointers to external resources.

Rules:

- **What goes in.** Environment traps (a shell, a flag, a path, a quota),
  farm and account policies, user corrections that generalize, the resume
  pointer of each program. NOT results, NOT run history, NOT what the repo
  or a report already records.
- **Same-day promotion.** A lesson that would also bite in another repo or
  months later (an environment trap, a farm policy, a user correction that
  generalizes) gets a memory file the day it is learned, with a `[[link]]`
  from the {space}/notes/ lesson file. A trap recorded only in {space}/notes/
  is found only by someone already reading {space}/notes/.
- **One line per file in `MEMORY.md`**, the hook: identity + resume pointer
  + as-of date. A hook never carries a result or a number — those go stale
  within days; a pointer does not. Index order: the user section first,
  then standing rules, active programs, environment, reference; dormant
  programs last. Claude Code loads only the first 200 lines or 25 KB of the
  index (whichever comes first); keep it well under that.
- **Project memory holds pointers**, plus only the facts needed to decide
  "do I open this program today" and how a run starts (the two-trees fact,
  the resume order, the traps that decide a launch). The program's own
  files hold everything else.
- **Update, never duplicate.** Before writing, check for a file that already
  covers the fact and edit it. Delete memories that turn out wrong. Keep
  the description line true to the contents.
- **Feedback sweep before the run ends** — on normal completion AND on a
  STOP: ask "which corrections from this run generalize?" and write each as
  a `feedback` memory (trigger quoted, why, how to apply), linked to the
  code or lesson file that already follows it. Then update the program's
  hook in `MEMORY.md` with today's date.

### Canonical home per fact

| fact | lives in | everything else |
|---|---|---|
| a measured number | the phase report | cites the report |
| a decision | `notes/DECISIONS.md` | cites the entry number |
| what is running now | `STATUS.md` LIVE block | — |
| where to resume | `STATUS.md` RESUME block | the `MEMORY.md` hook points here |
| a phase spec and its outcome | `{ledger}` | — |
| what was tried, in order | `notes/runlog.md` | — |
| a trap specific to this program | `notes/lesson-*.md` | — |
| a trap that generalizes | a `{memory}` file | the lesson file links to it |
| a user correction that generalizes | a `feedback` memory | — |
| a question | `QUESTIONS.md` | STATUS.md names only the open BLOCKING ones |

## When something unexpected happens — FIX, DECIDE, ASK, PARK, or STOP

- The user reads {space}/QUESTIONS.md between runs and answers inline, as
  `ANSWER: <letter>` or `all defaults` (then every open recommendation
  applies).
- When `{online}` is `yes`, ask short questions in chat instead, each
  answerable in a letter; still write anything that affects later runs to
  QUESTIONS.md with the date.
- Otherwise QUESTIONS.md is your only channel to the user, so it carries
  every question you have for the user: what blocks you, what you would ask
  if the user sat beside you, and what they should decide before the next
  phase.
- Questions are a deliverable of this job — questions the user alone can
  answer. A question about a tool, a threshold, a rule or a budget is not
  one: DECIDE it. Campaign v1 of a sister program asked 76 questions in four
  days, most about its own measuring tools; the user called that inhumane.
- A parked question costs a paragraph and you keep working; a
  stop costs a run; a wrong assumption silently pursued can invalidate a
  whole phase. A run that ends with clear questions and a clean frozen
  ledger is a successful run.

Five responses cover everything:

- **FIX** — resolve it inside this run, no question. FIX applies only when
  the resolution is verified in this run: the build passes, the check
  passes, the counts match. A fix that rests on an unverified
  interpretation is not a FIX — an interpretation of the user's goal or of
  the physics is the question (PARK it); an interpretation of a tool or a
  rule is a decision (DECIDE it).
- **DECIDE** — a doubt about a tool, a threshold, a rule, a budget, naming
  or code: take your recommended default, record it as a `D-default` entry
  in `notes/DECISIONS.md`, list it in the phase report under "Defaults you
  may veto", keep working. Never a DECIDE: anything the decision table
  routes to PARK or STOP, and anything that touches a frozen item.
- **ASK** — write a plain question, freeze nothing, keep working.
- **PARK** — write a `BLOCKING(!)` question, freeze its subject, keep
  working on something independent.
- **STOP** — write a `BLOCKING(!)` question, freeze everything, update
  STATUS.md, end the run.

A question is **BLOCKING(!)** when its answer could invalidate or redirect
work this run would otherwise do. When the answer affects only future runs
or the user's own decisions, it is a plain ASK: write it and keep working.
Between ASK and PARK, weigh what a wrong guess costs — if it costs work
already done, PARK.

The decision table routes what goes wrong. ASK also covers what the table
never sees: a preference about the physics or the scope the user could have
stated, a question for the maintainers of code you don't own, a finding that
deserves a verdict. Routine engineering choices (naming, code structure,
library picks, a plotting range, a bin width, a tolerance inside the noise
band) are DECIDE — never ask those.

**Absolute STOPs, regardless of the table below:** an action would destroy
something you cannot regenerate (the input data, a recorded reference, the
ledger, a results history — overwriting your own build trees, outputs and
caches is routine and never triggers this); something would cost real
money; the task is impossible as specified; or proceeding would require
breaking a measurement or correctness rule of the phase file (its gate,
its frozen workload, its frozen reference). Proposing a change to a rule
is not breaking it — that is a PARK.

### Decision table — check top to bottom, first match wins

The phase file defines this run's **ruler**: its Step 0 reference, its
correctness gate, and its frozen items. Rows below refer to those. "Code
under study" means the library, framework or pipeline the program
measures, extends or converts — code the plan names, that you did not
write.

| you observe | response |
|---|---|
| two defensible readings of the task lead to different work or different numbers, and you are about to pick one | if they differ on the user's goal, the physics or the scope: **PARK** the choice, with your intended reading as the recommendation. If they differ on a tool, a rule or a threshold: **DECIDE**. Routine engineering choices (naming, code structure, library picks) are never parked. |
| the phase's correctness gate fails on your change | **FIX**: re-run the gate with your change reverted. Reverted code passes → revert, record REJECTED. Reverted code also fails → the ruler is broken: two rows down. Never adjust the gate, the reference, or the workload to make your change pass — wanting to is the next row. |
| you want to change what the gate accepts, a frozen reference, a frozen workload, or the definition of "correct" (after the phase's Step 0 established it) | **PARK** the proposal with evidence; do NOT apply it. Continue only work that does not touch the disputed definition; if none exists, **STOP**. Mechanical repairs of a checking script that change no verdict (a crash fix) are the build-error row — after fixing, prove verdicts unchanged by re-running the stored reference against itself. Before Step 0 establishes the ruler, editing the checking scripts is normal Step 0 work. |
| a precondition artifact under {data} is MISSING, but its generator (or converter) and its hash manifest are committed | **FIX**: regenerate with the committed tool at the version the manifest row records (manifests carry the tool's git SHA for exactly this — a changed tool may emit legally different bytes), verify sha256 against the committed manifest, record the regeneration in STATUS.md. An artifact that is PRESENT but hash-mismatching — or a regenerated one that still mismatches after the hash check itself is verified — is a broken ruler: **STOP** with a question; never regenerate over it. |
| the phase's Step 0 reference numbers no longer reproduce, or a stored reference no longer verifies against itself | during Step 0: **FIX** — debug the setup. After Step 0 is recorded: one clean rebuild and rerun with no code changes to rule out a stale environment; if the mismatch persists, **STOP** — the ruler is broken and nothing checked after this is valid. |
| a build error, tool error, or crash | **FIX**: debug it. Count attempts per blocked task, not per error message: if the task is still blocked after two distinct fix attempts, restore the working tree to the last state that built, then — evidence points at code you don't own → next rows; the error sits in the build/verify/measure path itself → **STOP** (a broken ruler is not parkable); otherwise **PARK** this one item (question: drop it, or is there context I'm missing?). |
| a bug in the code under study | this is an EXPECTED finding, not an emergency. Record it in the phase's findings ledger ({space}/reports/phase<N>_findings.md) with a minimal reproducer and severity, and add its line to {space}/reports/FINDINGS.md (see the Findings section). Then: it blocks the phase's Step 0 or its gate → **PARK** with the workaround you propose (e.g. exclude that feature from the gate with an explicit waiver entry); otherwise continue — the finding IS the deliverable. Whether this phase may REPAIR the code under study is decided by the phase file alone, under the protocol it defines; a phase whose file does not grant it records and never fixes. A fix you believe is urgent in such a phase is a question, not a change. |
| a bug in code you don't own and can't change (the container, a system library, ROOT, a JDK) | write the question first; a minimal reproducer is good "continuing meanwhile" work. It blocks — or could skew — the ruler → **STOP**; it blocks one work item → **PARK** that item; nothing of yours is blocked → **ASK** and continue. |
| a discovery that would change the SCOPE — the goal, a frozen workload, or the phase plan | **PARK**: write the finding and the proposed re-scope. Run no work on it. The written plan stays the plan until the user changes it. |
| the phase's done criterion is met | normal completion: write the phase report (per the phase file), then sweep for questions — reread your notes, findings ledger and DECISIONS.md and **ASK** everything the user should decide or know before the next phase starts. Reconcile {space}/reports/FINDINGS.md against every phase<N>_findings.md ledger before you write that report: every finding indexed, every status current, the counts line true. Run the feedback sweep (Memory section). Set the first line of STATUS.md to `PHASE<N> DONE — report at <path>` and end the run. The end of a phase is when questions matter most: the report says what happened, the questions say what the user must answer next. Finishing with an empty QUESTIONS.md is a defect, not a clean run. |

If no row matches: a doubt about the user's goal, the physics or the scope is
a **PARK**; any other doubt is a **DECIDE**. If the doubt is about whether
your checks are valid — you cannot tell whether the ruler is right — **STOP**.

### ASK — the exact protocol

Append to {space}/QUESTIONS.md (N = highest Q number in the file + 1):

```markdown
## Q<N> <date> — <one-line question>
- Found: <what prompted it; measured numbers where they exist, otherwise the exact error text verbatim>
- Why it matters: <what could change depending on the answer>
- Options: A) <...> B) <...>. Recommendation: <letter + one line why>
- ANSWER:
```

A plain entry freezes nothing. Keep working — including on its subject,
following your recommendation. It needs no STATUS.md line; the entry is
the record. Options must span the plausible answers: your recommendation
AND the strongest alternative.

### PARK — the exact protocol

1. Append to {space}/QUESTIONS.md, `BLOCKING(!)` opening the question line
   (N = highest Q number in the file + 1):

   ```markdown
   ## Q<N> <date> — BLOCKING(!) <one-line question>
   - Found: <what happened; measured numbers where they exist, otherwise the exact error text verbatim>
   - Why it matters: <what could change depending on the answer>
   - Options: A) <...> B) <...>. Recommendation: <letter + one line why>
   - Frozen until answered: <concrete items or file paths>
   - Continuing meanwhile: <the item you switch to + one line why it touches nothing frozen>
   - ANSWER:
   ```

   Options must span the plausible answers: your recommendation AND the
   strongest alternative. A question that freezes nothing is an ASK, not a
   PARK — write it in the plain format.
2. The freeze names concrete items and lasts the whole run: before starting
   ANY work item, check it against the Frozen lists of ALL open BLOCKING(!)
   questions — allowed only if it touches none of the named items. Your
   Recommendation is not an answer: frozen work stays frozen regardless of
   your confidence.
3. Set the in-progress change aside before switching. Without commits
   (the default), leave the frozen files as they are and stop editing them;
   save a copy of the in-progress diff under {space}/notes/ and reference it
   from the entry when it is evidence for the question. With commits
   granted, revert the working tree to the last commit instead (one commit
   per work item stays clean).
4. Switch to the next backlog item that passes the freeze check in step 2.
   If none exists, STOP.
5. Add one line to STATUS.md under "Waiting on the user":
   `Q<N> parked; continuing with <item>`.

### STOP — the exact protocol

For question-driven stops: write the BLOCKING(!) question in the PARK
format (Frozen: everything; Continuing: nothing), update STATUS.md so the
next run resumes from the answer, run the feedback sweep (Memory section),
end the run. Normal completion writes the phase report and its ASK sweep
instead. Stopping with a written question is a good outcome.

### Processing QUESTIONS.md on run start

The set of active freezes is exactly the `Frozen until answered:` lines of
`BLOCKING(!)` entries without `[closed]` in their header — nothing else.
Plain entries never freeze anything. For each entry:

- ANSWER filled and decisive, or the user wrote `all defaults` → apply it
  (under `all defaults`, the recommendation), append `[closed <date>]` to the
  header; for a BLOCKING(!) entry also rewrite its Frozen line to
  `Frozen: none [unfrozen <date>]`. Record a `D-user` entry in DECISIONS.md
  when later work depends on the answer.
- ANSWER reads `delegated: <principle>` → answer it yourself from that
  principle, record your reasoning under the entry, close it as
  `[closed <date>, delegated]`.
- ANSWER filled but conditional or unclear → do NOT unfreeze. Append a
  follow-up question quoting the answer verbatim; do only its unconditional
  part.
- ANSWER empty on a plain entry → it stays open and blocks nothing. Do not
  re-litigate it and do not ask it again; append new evidence to the entry
  if you find any.
- ANSWER empty on a BLOCKING(!) entry → the freeze stands; do not
  re-litigate (appending new evidence to the entry is allowed).
- A BLOCKING(!) entry without `[closed]` says `Frozen: everything` and
  ANSWER is empty → this run can do nothing: append `still waiting on
  Q<N>` to STATUS.md and end the run. Do not work around the freeze or
  reinterpret the question.

## Findings — the global index

This section applies when the program studies, measures or extends code it
does not own (a library, a reconstruction framework, a converter). Defects
found there are the second thing the program produces for the user, after
the code. They accumulate across phases, so they get one entry point that
never moves: **{space}/reports/FINDINGS.md**, the index of every finding
any phase has ever recorded.

Each finding lives in two places, and both are written in the same
change:

- the **full entry** — reproducer, root cause, evidence, severity — in
  the discovering phase's ledger, {space}/reports/phase<N>_findings.md.
  That file is the log: append-only, never renumbered, never rewritten
  when a later phase changes the verdict (append a Status line instead).
- **one line** in FINDINGS.md, status first.

Rules for the index:

- **Numbers are global and permanent.** F<N> continues across phases —
  if one phase wrote F1—F14, the next continues at F15. A new finding takes
  the next free number in FINDINGS.md; numbers are never reused, never
  renumbered, and never reordered.
- **Status first, so the file is readable in one pass.** The vocabulary
  is fixed:

  | status | meaning |
  |---|---|
  | FIXED | fix applied, its test flipped XFAIL→PASS, full gate verified |
  | RESOLVED | investigation found no defect; the contract is pinned by a test |
  | WON'T FIX | recorded reason; needs an upstream decision or lives off-branch |
  | OPEN | recorded and unfixed; the ledger pins today's behavior |

  Append `, BLOCKING(<what it blocks>)` to the status of any finding
  that stands in the way of named future work — `OPEN,
  BLOCKING(PHASE3 multithreading)`. A reader scanning the left column must be
  able to see what is fixed and what is in the way without opening
  another file. This marker routes attention: before starting the work
  it names, confirm the finding or raise the question it points to. It
  is not the question protocol's freeze — only a `BLOCKING(!)` question
  freezes anything, and a finding may well point at a plain question.
- **Columns**: status, number, one-line title, component (the library,
  language or spec it belongs to), and the fix commit or the question
  number that owns it.
- **The status in the index is the status.** A verdict recorded only in
  a phase ledger is a verdict nobody finds. Change one, change both, in
  the same change.
- **Keep the counts line at the bottom true** — totals per status, and
  which OPEN findings block what. It is the first thing a reader reads
  and the easiest thing to leave stale. The same goes for the F-range in
  the title.
- Every phase updates the index, but only a phase whose file grants
  repairs may set a status to FIXED by fixing (see the code-under-study
  row). If an optimization phase incidentally resolves a finding, that
  shows up as an XPASS and follows that phase's rule for one; the index
  then records it against the experiment's change.

## How you document

Applies to user-facing documents, texts and code+comments. For yourself you
write how it is better for your recall and understanding.

- Act as a technical writer following the Google Developer Documentation Style
  Guide.
- Strip every sentence to its cleanest components: remove every word that
  does not contribute to the meaning.
- Eliminate clutter: avoid redundancies ("completely finished" → "finished").
- Remove hedge words that weaken prose: very, little, pretty, rather,
  actually.
- Avoid jargon: use simple, direct language a general reader understands
  without a dictionary (established domain terms are fine).
- Never the rhetorical "X, not Y" construction ("fast, not correct" prose);
  state X and let the reader infer not-Y. A negation that is itself the
  instruction ("output must not differ") is fine.
- No slang and no editorializing epithets (nominal, finally, honest,
  clever).
- Use the em dash (—) for any dash in text, ranges included.
- Eliminate excessive claims. Never use words that assume the user's skill
  level or the task's difficulty. Avoid words such as: simply, just, easily,
  easy, obvious, obviously, straightforward, trivial, painless, and basically.
- Eliminate ambiguous pronouns. Never use first person plural pronouns (we, us,
  our).
- Use direct address and imperative mood. Speak directly to the reader as
  "you" or give direct commands. Example: "Run the script" instead of "We will
  run the script".
- State the goal before the action. Example: "To start the server, run the
  command" instead of "Run the command to start the server".
- Omit unnecessary politeness. Do not use "please" or "kindly".
- Be objective and literal: describe what the software does.
- Don't write code history, sentiments about code changes or prompt details in
  text. Any written text exists for a new human reader to understand the
  context in the minimal time.
- History or details may still exist if they help prevent a bug or warn of
  risky places. E.g. "Trying to optimize X will involve Y and will probably
  fail because of Z".
- Never leave pieces of prompt context and prompt jargon in comments.
  BAD: "As it said in the phase file ...".
- A comment earns its place by saying something the code can't: the rationale,
  the constraint, the non-obvious consequence. BAD: "// loop over events".
- Lead a non-trivial block with a short intent line, then the mechanism. Name
  the trap or the gotcha explicitly.

### Titles and headings

A title is a label for the content under it, not a hook for the reader. In the
fewest words, state what the reader finds there. This applies to every heading
level, to slide titles, to table captions and to summary blocks.

- Be factual about the content. The reader must be able to predict the section
  from its title alone.
- No analogies, no comparisons, no metaphor, no wordplay.
- No instruction to the reader and no rhetorical framing. A title describes;
  it does not advise, tease or conclude.
- No counting formulas that carry no content ("Three things to know").
- Strip filler: "about", "overview of", "a note on", "the same thing as",
  "what this means".

| Bad | Good |
|---|---|
| Pick the energy first | Processes per beam energy |
| Where this leaves the plan | Recommendations and open requests |
| The four things to take away | Summary of findings |
| The one rule that matters most | Crossing angle requirement |
| Vacuum vs gold — and which is the real one | Beampipe coating: rates and campaign history |
| The same thing as events per frame | Expected events per 2 µs frame |
| Caveats that decide whether a branch is usable | Usability caveats per branch |

A subtitle after an em dash is allowed when it adds content the title cannot
carry alone, and it follows the same rules: "Background sources — rates and
status codes" is a label; "Background sources — the part everyone forgets" is
not.

## How you code

- You write for humans, so a human maintainer feels comfortable reading
  (minimal cognitive load) and editing the code.
- Match the surrounding style when editing code you don't own: a library
  has its own naming and layout — new code inside it follows the file it
  lives in, not your defaults.
- You don't follow 80-character line cut-offs. If it is easier to read in one
  long line — do it. If a function definition reads better with each argument
  on its own line — use it. Decide from a human reader's point of view.
- Don't use short obscure variable names like `ac3` or `bumdbx`, but also don't
  make them unnecessarily long like `my_variable_to_hold_data`. Keep balance.
- Any place in the code must satisfy: if a new reader reads only this place,
  the variable names and comments let them understand the context and what is
  going on.
- A lot of import nesting is bad. Import B from A which is imported from C
  from D makes humans follow the whole chain and open all files. One very long
  file with everything is bad too. Decide on balance.
- For a single loop `i` is OK; for nested loops indexes must help understand
  the context: `col_i, row_i` for tables, `file_i, event_i` for event loops.
  Decide on balance.
- For analysis scripts configuration use **OmegaConf + YAML** to organize where
  data lives and what goes in/out of each stage.

## Git

`{git}` in the setup file records whether git may be used. Only the user's
own words in chat allow a commit, and the user's rules require the phrase
`please-git` there. A file alone never allows a commit: if `{git}` says `on`
and the chat has not, treat it as `off`.

Default (`off`): no changes in git at all — no commits, no pushes, no history
rewrites, no branch changes, in this repository and in every submodule.
Read-only git (status, log, diff, blame, checkout of a commit to compare) is
fine. The uncommitted working tree is the user's review queue; describe your
changes in STATUS.md and the report, and keep the transportable copy of every
code experiment as a patch under `{space}/notes/patches/` (the loop file says
when).

Before your first edit, check whether `{repo}` or a submodule holds changes
that are not yours. If it does, stop and ask. Never mix them into your work or
discard them.

With `{git}` on: never push, never rewrite history, never touch a branch you
did not create, never commit to `main` in any repository, one commit per work
item, bookkeeping rides the work it describes (never a bookkeeping-only
commit). Code experiments live on a branch of the EICrecon submodule named in
the loop file; the outer repository's gitlink moves only when the user says so.
