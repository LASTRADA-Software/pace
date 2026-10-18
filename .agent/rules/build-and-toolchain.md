# Build system, toolchain and language pitfalls

Rules about the things that differ between compilers, standard libraries, hosts
and tool versions — and about the local gate that exists to catch them before CI
does.

Read this before changing a header everything includes, a randomness or timing
seam, `cmake/portable/CompileCache.cmake`, or anything a test harness's
determinism rests on.

## The local gate

<!-- agent-tripwire: **`bash <path>`, never the bare path** -->

`scripts/local-gate.sh` is the gate. Run it before pushing.

- **A hygiene check traverses each directory ONCE, not once per file pattern.**
  `file(GLOB_RECURSE var a b c)` traverses once PER PATTERN and the call site reads as
  one glob, so `check-sccache-backend-caveat` handed it ~19 patterns per root across
  two calls and cost **78.7 s against a 60 s budget** -- the documented local gate could
  not go green on a DrvFs checkout, a supported working environment (#502). Walk once
  and `list(FILTER ... INCLUDE REGEX)` the result; **never raise the timeout**, because
  a budget raised to accommodate a redundancy hides the redundancy.
- **That last clause is scoped to the redundancy, and the redundancy is gone.** Read
  unqualified it forbids the fix to #479, so it has to say what it was about. After the
  walk-once change there is one traversal per root and what remains is *irreducible* I/O:
  837 files read individually, ~12 MB, of which `src/` is 633 because a non-prose file
  naming a backend variable has to be forced into the exemption table rather than passing
  silently. There is no fat left for a larger budget to hide, so
  `sccache-backend-caveat`'s bound was raised to 180 s **and** — the part that matters —
  the check now MEASURES itself and prints the cost, the band and the headroom on every
  run. A bound may grow only beside an instrument that reports the margin it is spending;
  a number alone drifts back into the same state and nobody sees it happen.
- **Three figures for one check, all honestly taken, none carrying its conditions — that
  was the actual defect in #479.** The registration comment asserted `~0.2-0.5 s ... still
  far inside the timeout`; a quiet WSL 9p checkout measures ~4.5 s; two lanes measured
  53-57 s against the 60 s ceiling while several gates ran at once. Two orders of
  magnitude, and each read as a fact about the check when all three are facts about a
  **filesystem**. The oldest and most confident of them had nothing that could ever
  falsify it. Replacing an assertion with an observation is the fix; the timeout number is
  incidental to it. The bands and their conditions live in
  `PaceSccacheScanCostBands` — point at it, never copy a number out of it — and each
  row says whether its per-file figure was **measured or derived**, because two of the
  three are somebody else's wall time divided by a corpus count taken separately.
- **A bound on a check that cannot wedge is a backstop, not a deadline**, and conflating
  the two is what produced a 60 s ceiling this check spends 7% of on a quiet machine and
  95% of under ordinary lane load. `sccache-backend-caveat` opens no socket, spawns no
  subprocess, waits on nothing and has no unbounded loop — it reads N files and exits — so
  there is no hang for a wall clock to catch here, and the only thing it can catch is a
  filesystem slower than the widest measured band, which is a condition rather than a
  defect. Do not tighten it as though tightening a real deadline. It is defensible **only
  while a run going long says so**: the check narrates its measured per-file cost past
  `PaceSccacheScanNarrateAfterSeconds` — per scan root while walking, per hundred
  files while reading — and ctest captures the output of a test it kills, so a kill
  arrives with its reason attached. The one window it cannot narrate inside is a single
  `file(GLOB_RECURSE)`, which is uninterruptible and cannot be subdivided without
  reintroducing the per-pattern traversals #502 removed. The threshold and the bound
  cannot drift apart quietly either: the script **refuses** a budget below twice the
  threshold, because a run killed before narration could start is a bare timeout again —
  the signal that cannot say which kind of failure it was. `ctest -R sccache-backend-caveat-selftest` drives it, including the two negative
  directions that rot silently: narration ABSENT at defaults, and `SOURCE_DATE_EPOCH`
  reported as a frozen clock rather than as `0 ms/file`, which is an instrument measuring
  nothing while reporting the best possible filesystem.
- **Read that figure with its conditions, or it misleads in both directions.** The cost
  is per `stat` on a filesystem where each crosses a translation layer, so it is
  invisible on CI and on ext4 and it varies with page-cache warmth:

  <!-- table-total: none -->
  | check | filesystem | standalone | single gate | two lanes | budget |
  |---|---|---|---|---|---|
  | `sccache-backend-caveat`, before #502 | 9p | 78.7 s | 60.0 s (timeout) | -- | 60 s |
  | `sccache-backend-caveat`, after #502 | 9p | 4.0-5.1 s | -- | **53-57 s** (#479, three or four lanes) | 180 s |
  | `byte-order-qualifier` | 9p | 19.6 s | 28.6 s | **60.9 s** | 60 s |
  | `byte-order-qualifier` (#665) | **local ext4** | **0.217 s** | -- | **0.837 s** worst under load | 60 s |
  | `worker-refusals-counted` | 9p | 5.5 s | 9.7 s | -- | 60 s |
  | `net-boundary` | 9p | 4.0 s | 8.6 s | -- | 60 s |

  The two `sccache-backend-caveat` rows are the same check on the same filesystem with
  the redundant traversals removed in between, and they are the argument for reading the
  column headings: **standalone fell 16x and the contended figure did not follow it**,
  because what the walk-once change removed was traversals and what remains is 837
  individual file reads over a bridge. Do not read either row as the cost of that check;
  read the one whose conditions you are in, which is what the header row is for. The
  53-57 s column is the one figure here neither lane could afterwards reproduce, the
  machine having gone quiet — so it is DERIVED conditions, recorded as such.

  **The ext4 row is the falsification the model wanted, and it is why a filesystem
  column now exists.** Same check, same 645 files, same day: **0.217 s** quiet (8 runs,
  worst 0.223 s) and **0.655 s** average under load with a worst of **0.837 s** (8 runs,
  load average bracketed at 6.8 rising to 9.7). Both MEASURED, not derived. Against the
  9p row's 60.9 s that is a factor of roughly 280 for the standalone figure — and the
  check, the corpus and the code are identical, so **every one of these numbers is a
  reading of a filesystem and none is a property of a check.** A reader on ext4 who
  measures 0.2 s and concludes the budget is generous has made the same mistake as one
  on 9p who measures 28.6 s single-gate and concludes it is comfortable; both read a row
  that was not theirs.

  That is also why `byte-order-qualifier`'s registration comment said *"finishes in well
  under a second"* and went unchallenged for so long
  ([#665](https://github.com/LASTRADA-Software/pace/issues/665)): on the author's
  filesystem it was **true**, and it is true on CI. An assertion that is correct
  everywhere its author can run it, and two orders of magnitude wrong where the gate
  actually fails, has nothing that can falsify it from the inside — which is the same
  observation #479 made about the number it replaced.

  One traversal of `src/` is **2.09 s** (stable to 16 ms over five runs), and
  38 x 2.09 = 79 s predicted 78.7 s measured -- the model is falsifiable, which is what
  makes it worth trusting. **`byte-order-qualifier` has only ever exceeded its budget
  while a SECOND lane's gate was running**, and this repository routinely has two and
  three lanes gating at once. A reader who measures it single-gate gets 28.6 s and
  concludes it is comfortable; the condition is the finding, not the number.
- **The build tree was NOT the cause, and assuming it was would have shipped a fix that
  changed nothing.** Deleting `out/` entirely takes `sccache-backend-caveat` from 100 s
  to 79 s -- measured A/B, ratios 1.0-1.3x across all ten globbing checks -- so "no
  check walks a build tree" would have been implemented, measured as done, and the gate
  would still have been red. The ticket's own mechanism section said so before the
  wrong scope was written over it: *`out/` is not a scan root; it is the source tree,
  walked 126 times.* Globbing a build tree is a real and separate mistake, and one this
  project has also made.
- `ctest -R glob-traversals` enforces one pattern per call and refuses an unquoted
  `${globs}` expansion -- ONE argument and as many traversals as the list is long,
  which is what the original defect was and what an argument count alone would pass. It
  is a **proxy** for traversals-per-root and its header says so: nineteen
  single-pattern calls in a loop cost the same and pass it, so tidying an argument list
  into a loop makes the guard greener while reintroducing the cost.
  `glob-traversals-selftest` drives seven trees, two of which exist because the check
  got them wrong while it was being written -- it reported its own remediation example
  printed from a `message()`, and a stray `]` in a comment merged lines under CMake's
  list grouping so it named line 217 for a call at line 307.
- **Read a hygiene check by the COUNT of what it says it examined, never by whether it
  passed.** `check-script-check-signals` was green while reading 3 of 21 registrations
  — 14% of its subject — and no verdict could have shown it, because pass/fail was
  green on both sides of the blindness. It was found by running every check against
  master's tree and the branch's tree and diffing the counts each one reports; exactly
  one differed. Two of the five bracket-vulnerable splitters could ONLY be caught this
  way. A vacuous-pass refusal is orthogonal and not a substitute: it catches TOTAL
  blinding and is structurally incapable of catching partial, since 3 is not 0. And
  loud-versus-silent is a property of WHERE the bracket lands, not of the check — the
  same check refused outright under one bracket position and passed at 14% under
  another — so no check may be assumed safe because it once failed loudly. And only an
  UNBALANCED bracket groups: `[[nodiscard]]` is completely harmless. The tree said
  `[` and `]` were "reserved", which is broader than the truth, and acting on the
  broad rule is how the fix for this took `check-worker-refusals-counted` from three
  refusal spellings to ZERO — neutralising brackets destroys text a check matches on.
  Where brackets must survive, do not neutralise them: read the lines without ever
  building a CMake list, which is immune by construction rather than by convention. And know
  what the method CANNOT see. A count detects a check examining a DIFFERENT NUMBER of
  subjects; it is blind to one examining the same number of DIFFERENT subjects. So it
  validates a change that alters HOW MUCH a check reads, and never one that alters WHAT
  it matches — a dropped escape or a normalised tab leaves the line count identical and
  the matched text different. The consolidation in
  [#495](https://github.com/LASTRADA-Software/pace/issues/495) was nearly
  validated this way, by the very method this bullet recommends. A tool that cannot
  fail in the way a change fails is not validation, it is decoration.
- **A bracket-vulnerable reader is judged per (reader, file, surviving lines) — never
  per script — and the verdict flips on the corpus alone.** Measured across the six
  remaining `file(STRINGS)` readers, by injecting one unbalanced `]` into a comment on a
  line the reader KEEPS:

  <!-- table-total: readers=rows -->
  | reader | verdict |
  |---|---|
  | `check-tsan-scope:109` | clean pass -> hard refusal, **LOUD** |
  | `check-node-config-reference:75` | clean pass -> hard refusal, **LOUD** |
  | `check-net-boundary:169` | passed over a REAL violation, **SILENT** |
  | `check-psk-signing-seam:216` (retired at #178 with the key) | 15 calls counted -> 14, still passed, **SILENT** |
  | `check-vslang-probe-only:122,198` | unchanged — **by coincidence, not defence** |
  | `check-script-check-signals:256` | unchanged — `LIMIT_COUNT 1`, immune by construction |

  The last two rows are the point. A merge can only reduce a count where ONE FILE holds
  two or more matching lines with the bracket on a non-final one; `check-psk-signing-seam`
  and `check-vslang-probe-only` are the same reader shape and land on opposite sides
  purely because one corpus has a two-match file and the other does not. Injecting into a
  one-match file changes nothing, which is why the first attempt on the psk check came
  back clean and would have closed it as safe. **A reader left alone because today's files
  happen to be safe is a defect scheduled for later**, and `LIMIT_COUNT 1` is the only
  row in that table that is safe for a reason rather than by luck.
- **The remedy is not one remedy, and applying the usual one to `check-tsan-scope` breaks
  it.** Blanking `[` and `]` before splitting is right where the brackets are punctuation;
  it is wrong where they are the DATA. A Catch2 tag is spelled `[async]`, so the neutralising
  split made that check report the table as naming no tags at all and refuse on a perfectly
  good tree — measured, because that was the first attempt at the fix. The standing rule
  above already says *where brackets must survive, read the lines without ever building a
  CMake list*; that reader is now a `FIND`/`SUBSTRING` offset walk, immune by construction,
  and the rule is carried by the reader it governs rather than by a file three directories
  away.
- **`if(VAR STREQUAL "")` does not fire when VAR is UNSET, and the one place that matters
  is a glob that came back empty.** `check-net-boundary`'s empty-directory guard — whose
  own comment calls it *"the one failure mode a boundary test must not be allowed to
  have"* — could never fire. `file(GLOB_RECURSE)` over an empty directory yields an empty
  list, `set(x ${empty})` **unsets** x, and CMake then reads the left operand as the
  literal string `unitSources`, which is not `""`. Measured:

  ```
  set(empty_list)
  if(empty_list STREQUAL "")       did NOT fire
  if("${empty_list}" STREQUAL "")  FIRED
  if(NOT empty_list)               FIRED
  ```

  The sibling accumulators in the same file are safe only because a `set(x "")` above
  DEFINES them; the broken one is assigned inside a loop from a glob. So the hazard is not
  the idiom, it is the idiom applied to a variable whose assignment can vanish — and the
  check reported *"0 source(s) across 2 directory/directories reach only themselves"* and
  exited 0 over a tree with no sources in it at all. **Quote the variable.**
- **CMake unescapes a quoted argument BEFORE the regex engine sees it, so a regex literal
  needs `\\.` and not `\.`.** Written `"\.(cpp|cc|cxx|hpp|hh|hxx|h|ixx|cppm)$"`, the pattern
  arrives as `.(cpp|...)$` — a dot matching ANY character. **It is not a near-miss that
  merely widens the set slightly**: `check-apt-update.sh` matches it, because `.sh` is
  any-character followed by the `h` alternative, and a file enumeration written that way
  returned **79 shell scripts** as first-party C++. Every downstream verdict stayed green,
  because a shell script contains no C++ for a C++ rule to object to — so the over-broad
  half of this is invisible by construction and only a COUNT compared against an
  independent one finds it (`git ls-files | grep -cE`, 1090 tracked C++ against the
  helper's 1169). Same family as the `pkill -f` and `grep -Lq` entries: the shell or the
  tool obliges, nothing errors, and the output looks right. Sibling trap, one level up: a
  `macro()` re-parses its arguments textually, so there a backslash is eaten TWICE.
  - **And the instrument used to find it can invent a second finding.** The first diff of
    the two lists also reported `src/CowTree/*` as missing from the enumeration, which was
    false: the CMake-written list had different line endings from the `git ls-files` one, so
    `comm` matched nothing at all and `head` showed the front of each list as though it were
    a difference. The real defect was the pattern alone. **A comparison of two file lists on
    this host states its line endings**, or it reports a superset of what is wrong — and the
    extra findings look exactly like the real one.
- **A clean-tree injection understates a check that only reports violations.** #518
  classified `check-net-boundary` as PARTIAL — summary byte-identical, full output changes
  — from exactly that experiment, and the classification is too kind: everything a merged
  element swallows is something the check had nothing to say about, so on a clean tree
  nothing changes at all. Three arms with a violation PLANTED:

  ```
  violation alone                     exit 1, violation NAMED, 33 lines
  violation + a stray `]` before it   exit 0, violation NOT named, 1 line
  stray `]` alone                     exit 0, clean
  ```

  The third arm is not decoration: without it a check that refused every bracket would
  pass the second for the wrong reason. **An injection is evidence only if the thing it is
  meant to hide is there to be hidden** — the STORE lane's *a green probe of the wrong
  shape is not a refutation*, met from the other direction.
- **A census cannot falsify a premise — it can only produce a number consistent with it.**
  A count is taken THROUGH a claim. The pattern, the file set, the exclusions and the
  question itself are all chosen by somebody who already holds the premise, so whatever the
  tree looks like the number that comes back is consistent with it. That is not a miscount
  and no amount of counting more carefully reaches it: the instrument had no way to
  disagree. The bullets above are the version where the pattern is wrong; this is the
  version where the pattern is right and the premise behind it was never tested.

  So **re-derive an inherited claim BEFORE the census, never after.** The ordering is the
  whole rule, because afterwards the census has already told you what you expected to hear,
  and the re-derivation collapses into confirming that the source says what the number
  showed. Reading for confirmation stops at the first line that matches — the handoff rule
  in `AGENT.md`'s *Caching an expensive repeated answer*, arriving in an audit.

  And **agreement between a fresh measurement and a source you have not read is worth
  nothing**, because the two readings are not independent: they share the premise, so they
  cannot disagree about it. It nonetheless *feels* like corroboration, which is what makes
  this worth a bullet rather than a sentence — the same tell as *three arms agreeing
  perfectly is what a broken instrument looks like as well as what a real pattern looks
  like*, one level up from the instrument and in the reasoning around it. The testing lane
  carries the same rule where the subject is a model's arithmetic rather than a tree's
  files ([`testing.md`](testing.md)).
- **A census states its PATTERN, not only its number.** Two independent audits of the
  same file set differed by exactly one, and neither party had miscounted — they had
  counted through different patterns:

  <!-- table-total: none -->
  | pattern | cac9bda, all | cac9bda, excl. selftests | HEAD |
  |---|---|---|---|
  | `scripts/check-*.cmake` (the glob a ticket names) | **20** | **18** | **34** |
  | `grep 'check-.*\.cmake$'` (unanchored) | 21 | 19 | 36 |

  The whole difference is `scripts/script-check-canary.cmake` — and at HEAD also
  `script-check-warning-canary.cmake` — because *"script-**check-**canary.cmake"*
  contains `check-`. The unanchored form matches them; the glob does not. That is the
  `pkill -f` lesson arriving in a `grep`, twice in two days: **a pattern is broader than
  its author reads it as**, and a bare number carries no way to tell which pattern
  produced it.

  Worth recording that the second instance was a MANAGER quoting a corrected number back
  to a developer — the correction was wrong for the same reason as the thing it was
  correcting. Nobody is outside this; the remedy is that the pattern travels with the
  figure, not that people count more carefully.

- **A listing that came back AT its `--limit` is a real answer about a set that is not
  the whole set** ([#724](https://github.com/LASTRADA-Software/pace/issues/724),
  closed). Nothing about the rows distinguishes it: the cap reads as the total, and the
  reading is wrong in the SMALLER and therefore unsuspicious direction.

  Measured twice. `gh project item-list` truncating silently produced two wrong board
  figures that were reported onward — 300 and 121-with-44-Todo against a real 356 and
  147-with-52 — and `build.yml`'s clang-tidy notifier stops de-duplicating past 500 open
  issues, at 161 today.

  **Raising the limit is not the fix**: it moves the cliff and hides that there is one,
  which is the timeout argument from the top of this file wearing a different number.
  The fix is that a listing at its cap SAYS so, which is what `scripts/ci-report-issue.sh`
  does and what `ctest -R gh-listing-seam` requires of every other caller — a `gh`
  listing goes through that seam or carries a stated reason why it does not.

  Where a question can be asked so that truncation is impossible, ask it that way
  instead: the search API's `total_count` is a count of the whole set rather than a page
  of it.
- **A stated total beside a table is DERIVED from it, or it is a second claim.** A
  hand-maintained number describing a hand-maintained list is two sources of truth
  wearing one hat: editing the table does not update the number, nothing checked that it
  did, and the failure is silent because the sentence still reads correctly. Measured on
  ONE table across THREE consecutive commits — `.agent/rules/metrics-and-observability.md`'s
  four-states table — where each commit fixed the previous count and introduced the next,
  all three by the same author, in the same file, on the same day, with the rule about
  instruments that miscount open in the next tab
  ([#780](https://github.com/LASTRADA-Software/pace/issues/780)). At three
  occurrences it is not a discipline problem: prose did not prevent it and re-reading did
  not prevent it. It is the `RowsInEnumeratorOrder` argument arriving in markdown — the
  count comes from the table or it is not a count.

  `ctest -R table-totals` derives it. Two decisions are recorded in the check rather than
  in a commit message, because picking either silently is what the ticket refuses:
  - **The multipliers are PARSED, not banned.** That table's rows carry `(twice)` and
    `(three times)`, so 8 rows describe 12 collapses and the prose states BOTH figures. A
    checker that counts rows is wrong for exactly the table that motivated it, and wrong
    in the direction that looks right — `8` beside a table of 8 rows is entirely
    plausible. Two quantities, two modes, both derived. A multiplier the check cannot
    read is a REFUSAL, never a silent 1.
  - **The marker is MANDATORY, and `none` is how a table says it has no total.** Not
    opt-in: an opt-in marker is exact about the tables it knows and silent about the ones
    it does not (#492). That is the `Refuse` / `RefuseWithoutCounter` idiom from
    [`metrics-and-observability.md`](metrics-and-observability.md) — *deliberately
    uncounted must not be spelled like forgot* — costing one comment line per table and
    buying the property that a table ARRIVING cannot join the tree unchecked.

  Three things the implementation got wrong first, all found by watching rather than by
  reading, and all the same family as the bullet above:
  - **The scope census was wrong by 100%.** An `^\|`-anchored scan found 10 tables and
    was silent about 10 more, because a table INSIDE a bullet is indented. The scope
    decision was then argued from the wrong number, and the miss surfaced only because
    one skipped table happened to catch the eye — which is the census bullet's own lesson
    met while implementing the check for it.
  - **The figure NEAREST a table is the one that describes it.** A first-match search read
    the four-states table as claiming 4, because its paragraph legitimately states the
    older "five separate times, in four different instruments" as well as the current
    "twelve collapses across eight instruments". The check refused a CORRECT tree, which
    is how it was found.
  - **A number need not sit immediately before its noun** — "the six remaining
    `file(STRINGS)` readers" is two words apart — and a marker forced to spell the
    intervening words would be a copy of the sentence, which is a third source of truth.

  **What is deliberately NOT checked**, recorded because the ticket asked: `AGENT.md`'s
  tripwire restates *"five times in four instruments in one session"*. That figure is not
  derived from the table — it describes the FIRST session, five of the twelve — so
  asserting it against the table would assert a wrong thing.
- **A scan whose needle can appear in its own source, or in the text it reports, will
  match itself.** The guard added for
  [#678](https://github.com/LASTRADA-Software/pace/issues/678) scans
  `check-e2e-helpers.sh` for direct increments of its failure counter, because the
  property it protects — that `note_failure` is the only thing that touches the counter,
  so a failure cannot be counted without being named — holds only while that is true.
  It scans its own file. Its first run reported **three** increments where there is one,
  and it was right: the needle appeared verbatim in the needle, in the `grep` argument
  and again in the `grep -n` that prints the offending lines.

  It failed in the safe direction — it refused rather than reporting a wrong verdict
  about the subject — and it was still wrong, which is the half worth keeping.
  **Failing closed is not the same as being correct, and a guard that refuses valid
  input is a guard somebody deletes.**

  **The remedy is construction, not exclusion.** Spell the needle so it cannot be its
  own match — a regex with `[+]` where the literal has a `+`, an anchor, a character
  class — rather than subtracting the known self-hit. **An exclusion list grows and a
  construction cannot**: the next site that happens to contain the needle is a defect
  the list has to learn about, while a needle that cannot match itself is finished.

  Distinct from the pattern-breadth entry above, and the two are easy to confuse
  because both end in a count that is too high. There the needle matched something
  **else** that legitimately contained it (`script-check-canary.cmake` contains
  `check-`); here it matched the **scan's own text**. The tell is whether removing the
  scan changes the count.

  A second instance was reported in the same session and is **not verifiable from this
  tree** — a settle check written as `grep -q "tests failed"`, which matches inside
  `0 tests failed out of 57` and so reads a clean run as a failing one. Recorded as
  reported rather than measured, because the code was never committed; it belongs here
  because it is the *other* half of the rule, where the needle appears in the text the
  instrument **reports** rather than in the text it is written in.
- **"Only 4 of 16 defend" was wrong when it was written, and no slicing recovers it.**
  #510's denominator matches nothing on its own cited ref: not 20, not 18, and not the
  **13** that read file content. Today there are 34, none added by the branch that
  audited them. **A ticket cannot be closed against a count that no longer describes the
  tree**, so the acceptance became a per-reader audit and the consolidation stayed with
  [#495](https://github.com/LASTRADA-Software/pace/issues/495), which is where
  `check-glob-traversals.cmake`'s own comment already sent it. Absorbing it would have
  closed one ticket by silently swallowing another.
- **A count asserted in prose is a claim nothing verifies.** Two comments went stale in
  one session, both because the thing they counted changed underneath them and nothing
  was watching. "This is the fourth copy of this idiom" was counting the SPLITTER when
  it was written and now reads as a claim about `pace_globs_to_regex`, of which
  there are three. A note asserting `src/tests/CMakeLists.txt` holds 25
  `$<TARGET_FILE:>` references survived a rebase that added a registration only because
  that registration happened to use `${CMAKE_COMMAND}` — true by luck, not by
  construction, and it would have gone false silently. Both were written by someone who
  had just spent hours on exactly this failure mode. So prefer prose that states the
  INVARIANT ("each root is walked once") over prose that states a census ("there are
  three copies"), and where a number is genuinely load-bearing, put it where a CHECK
  reads it rather than where only a human does — which is what `check-glob-traversals`
  does for the count that matters.
- **An instrument whose failure mode is an empty or unexpected value must not have a
  predicate that sorts it into a named outcome.** Two instruments invented their
  subject in one session, both by a negation quietly catching a value nobody
  enumerated.
  - A `gh ... --jq` query whose escaping the shell had mangled printed a parse error
    and returned nothing; the surrounding `${res:-JOB NOT PRESENT}` turned that
    nothing into a confident sentence, **identically for all four runs queried**. The
    reading was the exact opposite of the truth — the job runs and passes. The tell
    was that all four rows agreed *perfectly*, which is what a broken query looks like
    and also what a real pattern looks like, so agreement is not corroboration when
    the instrument can fail wholesale.
  - `gh run view --json jobs` renders a **running** job's `conclusion` as the empty
    string, not `null`, so `select(.conclusion != null and ...)` matched every
    in-progress job and reported it as FAILED. That is *unfinished* classified as
    *failed* — the four-states rule in
    [`metrics-and-observability.md`](metrics-and-observability.md), violated by the
    predicate rather than by the author. The tell was walked past: a required check
    failing in a merge queue after passing on the PR, on a byte-identical tree, is not
    a plausible event.

  So: check the query's own exit status rather than only its output; **enumerate the
  states and print counts**, so an unexpected value shows up as unexpected instead of
  falling into whichever bucket a negation happens to catch; and never let a default
  substitution convert "I could not see" into a statement about the subject. A query
  that failed and a subject that is absent are different findings, and a `:-` default
  spells them the same way.
- **A hygiene script `ctest` runs is constrained to bash 3.2, because macOS ships
  bash 3.2.** Apple has not shipped bash 4 since the licence change, so `/bin/bash`
  on the macOS runner is from 2007. A script registered in the **default** ctest
  set runs on every platform CI builds, and the constraint is invisible from the
  Linux box such scripts are written on. The bash-4 constructs to avoid are few
  and worth knowing by name:

  <!-- table-total: none -->
  | avoid | use |
  |---|---|
  | `mapfile` / `readarray` | `while IFS= read -r x; do a+=("$x"); done < <(...)` |
  | `declare -A` | parallel arrays, or a `case` |
  | `${var^^}` / `${var,,}` | `tr '[:lower:]' '[:upper:]'` |
  | `local -n` | pass the value, or use a global with a stated name |

  Keep the **process substitution** when replacing `mapfile`: a pipeline into the
  loop reintroduces the `pipefail` trap recorded below, where a `grep` that matches
  nothing takes the script down.

  This is the section's own subject arriving through a door it did not name.
  `merge-queue-contexts` used `mapfile`, passed everywhere it was developed, and
  failed only on `macOS-clang-release` with `mapfile: command not found`. And the
  constraint was **already known**: `scripts/coverage.sh` carries a comment saying
  exactly this, in a place only a reader of `coverage.sh` would find it. A lesson
  recorded where it cannot be reached by the next person who needs it has not been
  recorded. The same holds for the
  `mapfile` and `declare -A` inside `pr-labels.yml`.

  **`scripts/tidy-sweep.sh` is the exception, and how it is one is the rule.** It
  uses `mapfile`, `declare -A` and `wait -n`, which are intrinsic to the scope
  computation rather than incidental to it, so it cannot be written to 3.2 the way
  the fixtures above are. It is registered in the default `ctest` set anyway
  (#588), because the alternative was the state it was in: the only thing running
  its self-test was the `clang-tidy` job whose scope it computes, which is not an
  independent check of anything. What makes that safe is that **below its floor it
  exits `77` and the registration carries `SKIP_RETURN_CODE 77`**, so a stock macOS
  runner reports SKIPPED rather than red -- and the message says a skip is not a
  pass. Skipping is the fourth state, not a quiet success.

  Two ways to get this wrong, and they are symmetric: registering such a script
  without the skip code turns a silent non-registration into a red macOS leg, and
  "repairing" that by dropping the registration on macOS at configure time puts it
  back to a check that does not exist and does not say so. The guard cannot live at
  configure time in any case -- the floor is a property of whichever `bash` the
  machine has at RUN time, and a macOS runner can carry 3.2 at `/bin/bash` and 5.x
  from Homebrew, which `if(NOT WIN32)` cannot tell apart.

  It is also a live instance of [#336](https://github.com/LASTRADA-Software/pace/issues/336):
  `local-gate.sh` cannot run in an agent-created Windows worktree, so nothing
  exercised this before CI did.

- **A local gate cannot see a configuration it does not build, and advice nobody
  runs is not a gate.** `scripts/local-gate.sh` is that advice as a script:
  clang-format at the pinned version, then `clang-debug` and `gcc-release`, refusing
  to run `ctest` against a build that did not complete. It exists because this
  paragraph was already here and was skipped twice in one branch -- once for a GCC
  `-Wnull-dereference` through an inlined `memcpy` that clang emits at no level, and
  once for a clang-tidy check the binary on `PATH` had never heard of. Both cost a
  full CI cycle for a configuration the developer already had.

  The default agent
  preset is `clang-debug`: one compiler, one standard library, `-O0`, sanitizers on.
  CI is four more — GCC at `-O3`, clang-cl, MSVC, and clang against **libc++** on
  macOS — and each of the three defects that reached CI on the Raft branch was
  invisible to every configuration below it. GCC 14 at `-O3` reports
  `-Wnull-dereference` inside `std::optional::value_or` where clang does not;
  clang-tidy 22 knows checks clang-tidy 20 has never heard of; and libc++'s
  `uniform_int_distribution` is a different function from libstdc++'s. Before
  pushing a change that touches a header everything includes, a randomness or
  timing seam, or anything a test harness's determinism rests on, build **at least
  one release configuration and one non-clang compiler** locally —
  `cmake --preset gcc-release` and `clang-release` both exist and both run in WSL.
  - **libc++ does not have every C++23 library feature libstdc++ has, and the
    failure is a compile error on one platform only.** `std::views::enumerate`
    compiles under GCC 13's libstdc++ and does not exist in libc++ at all, so
    `FleetView.cpp` built clean locally and broke the macOS package job -- a
    configuration whose *first* compile of the change is in CI. This is a different
    shape from the `uniform_int_distribution` case above: not two implementations
    disagreeing, but one of them not shipping the header's contents. Before reaching
    for a C++23 *library* facility that this codebase does not already use
    somewhere macOS compiles, check that it does -- `grep` for it in non-test code
    is enough, since the package job builds the library and every app. The
    workaround is nearly always a C++20 spelling: `std::views::iota` over the
    index range says what `enumerate` says and is ten years older.
  - **A facility can be PRESENT and still not have the overload you want -- which makes
    the remedy above give a FALSE PASS.** `std::from_chars` has no floating-point
    overload in libc++ before macOS 26.0, which is what the `macos-14` runners have, so
    `std::from_chars(first, last, someDouble)` compiles on libstdc++ and on MSVC and
    fails to BUILD on that one leg. Every *integral* `from_chars` in this tree is fine
    and there are many of them, so the bullet above's remedy -- grep for the facility in
    non-test code and see that macOS already compiles it -- answers YES and is wrong.
    **A grep tests a NAME; the hazard is a SIGNATURE**, here the third argument's type.
    This is a third shape rather than a restatement: not two implementations disagreeing
    (`uniform_int_distribution`), and not one of them failing to ship the contents
    (`views::enumerate`), but a name that is present with one overload missing, so the
    check that catches the second shape reports clean on this one.

    `Core/NumericText.hpp`'s `ParseFiniteDouble` is this tree's one answer. Reach for it
    rather than writing the call; it also pins the C locale, which the obvious
    `istringstream` spelling does not, so a host whose `LC_NUMERIC` is not `.` still
    reads the format this project's own `std::format` writes. It was `RedisResp.cpp`'s
    private `ParseDouble` and was **moved** rather than copied when `pacectl`
    became its second caller -- a second implementation citing the first in a comment
    vouches for its bugs without inheriting its fixes.

    It has cost a red `macOS-clang-release` once (PR #1198), written by an author who had
    the correct implementation *and its reasoning* sitting in the same tree, in a comment
    only the RESP handler's readers ever see. That is the whole reason the function
    moved: a new file's author has no occasion to open the RESP handler, and the natural
    thing to write is the call that does not build on one platform.

    **No scan enforces this, deliberately.** A regex over `from_chars` matches every
    correct integral call in the tree and cannot see the argument's type, so a check
    would be noise -- and noise is how a guard gets deleted. The macOS leg is the
    enforcement; this bullet is what saves the cycle. What *is* asserted is the
    function's own behaviour: `Core/NumericText_test.cpp` covers the grammar's edges and
    the locale property directly, and the locale case fails when the `imbue` is removed,
    which no wire-level test in `RedisResp_test.cpp` can see. Its finiteness guard is
    dead code today and says so at the site, because a reader who works that out alone
    reads it as a defect.

  - **And "macOS already compiles it" names TWO standard libraries.** `macOS-clang-release`
    builds with Homebrew's LLVM and its current libc++; `Package (macOS .pkg)` builds with
    AppleClang over Apple's OWN, older libc++ -- the split *Packaging and coverage stay on
    pull requests* below records, and the one `views::enumerate` fell into. PR #1392 added
    `std::ranges::iota` (in `DashboardPanel.cpp`) and `std::ranges::fold_left` (in
    `FrameEndpoint.cpp`), went green on every required context including
    `macOS-clang-release`, and the package job answered `error: no member named 'iota' in
    namespace 'std::ranges'` (run 34824219289). That job is **not a required context**, so
    the remedy above -- *grep for it and see that macOS already compiles it* -- can be
    satisfied by the wrong macOS, and the failure lands after the merge, on whoever packages. A build also stops at its first failure, so the `fold_left`
    behind the `iota` was never reached: fixing the reported site alone would have moved the
    red one file along.

    The owner's call was to KEEP the C++23 spelling rather than retreat to `std::iota` and
    `std::accumulate`, so `Core/Ranges.hpp` carries a seam: `Ranges::Iota` and
    `Ranges::FoldLeft`. What makes it the right shape, and what to keep if it is extended:
    - **Selected by the feature-test macro from `<version>`, never by compiler ID or
      version.** The macro is the library's own statement of what it ships. Where it is
      defined the seam is an object of the standard function object's own TYPE, so nothing
      changes on a leg that already built; where it is not, the seam is a transcription of
      [numeric.iota] / [alg.fold] with the standard's constraints and return types.
    - **A facility can be present with its macro ABSENT, and that is harmless.** Measured on
      libc++ 22: `__cpp_lib_ranges_iota` defined, `__cpp_lib_ranges_fold` not, although
      `fold_left` is implemented -- inferred to wait for the whole P2322 family. So every
      libc++ build selects the `FoldLeft` fallback, which means `macOS-clang-release` RUNS it.
    - **The fallback is compiled and tested on EVERY platform**, under `Ranges::Detail`,
      and held to agree with the standard facility wherever one exists. A fallback compiled
      only where it is selected is compiled only on the leg nobody builds locally.
      `PACE_RANGES_FORCE_FALLBACK`, as a WHOLE-BUILD define only (a per-TU define is an ODR
      violation), selects it everywhere so a Linux or Windows build can compile the real call
      sites against it -- the only local stand-in for Apple's libc++.
    - **A copy of the function object, not a reference, and `Iota` rather than `iota`.**
      clang-tidy files a `constexpr auto const&` under global VARIABLES (camelBack) because a
      reference type is not const-qualified; a copy is a global CONSTANT. The alternative, an
      `IgnoredRegexp` in `.clang-tidy`, would be a second list of seam names, and the case
      difference is what lets a case-sensitive scan tell `Ranges::Iota` from `ranges::iota`.
    - **Enforced, unlike the bullet above:** `ctest -R ranges-seam`, in the default set,
      refuses a direct `std::ranges::<name>` in first-party C++ for every name the header
      wraps. The difference from `from_chars` is that here a NAME is the hazard, so a scan
      sees exactly it. The wrapped set is DERIVED from the header's selection blocks -- a
      restated list catches a facility leaving and is blind to one arriving -- and the file set
      from `git ls-files` minus `scripts/lib/third-party-roots.txt`. Its line walk is
      `pace_scan_code_lines` in `scripts/lib/CheckCommon.cmake`, moved there from
      `check-istreambuf-iterator.cmake` when this became its second caller.

    **The next missing facility is a selection block in `Core/Ranges.hpp`, never an `#if`
    at a call site**: a guard at the site re-derives the selection per file, and the arm a
    local build never compiles is the arm that breaks.

  - **And the mirror holds: a Windows verification is green about a smaller set of
    questions than it looks.** The paragraph above counts what a Linux-only gate
    misses; this direction is measured too. One session's four tickets produced
    **four defects a fully green MSVC run of ~2997 tests could not have reported** --
    a partial designated initializer (`-Wmissing-designated-field-initializers`,
    which clang makes an error and MSVC does not diagnose at all), a leaked coroutine
    frame in a test fixture (ASan; no Windows preset runs a sanitizer), and two
    clang-tidy findings on code MSVC compiles happily
    (`readability-redundant-typename`, `performance-unnecessary-copy-initialization`).
    Not one of the four is reachable by running *more tests* on Windows: three exist
    only in the analyser and the fourth needs a sanitizer. So the inference to refuse
    is "the Windows run was green, therefore it was green about everything" -- the
    Windows leg answers a different question, not a weaker version of the same one.
    Four in four tickets is recorded rather than one anecdote, because a rule argued
    from a single instance reads as an accident.
- **`clang-format` and `clang-tidy` after every change — at the build CI pins.** The style
  job runs the PyPI clang-format release `.clang-format-version` declares, and the clang-tidy
  jobs the PyPI clang-tidy release `.clang-tidy-version` declares (the bullets on each build
  below); successive LLVM releases do not agree with each other: the style job compares
  against a *newer formatter*,
  and the clang-tidy job enables *checks that did not exist* in an older one. So a tree that is
  clean under whichever binary happens to be on `PATH` can still be rejected — a red build for
  code nobody mis-wrote, and one no local run catches unless it uses the same version. Name the
  version explicitly rather than relying on `PATH`:
  `git ls-files '*.h' '*.hpp' '*.cpp' | xargs "$(bash scripts/check-clang-format-version.sh --resolve)" --dry-run --Werror --style=file`,
  and, for the analyser, the build `.clang-tidy-version` declares
  (`-DCMAKE_CXX_CLANG_TIDY="$(bash scripts/check-clang-tidy-version.sh --resolve)"`, see the
  bullet on the analyser's BUILD below) **in a build directory of its own**. Found three
  times in one branch: four files reformatted by 22 after 20 had passed them, four
  `find(...) != npos` tests that only 22 reports as `readability-container-contains`, and five
  `std::lock_guard`s that only 22 reports as `modernize-use-scoped-lock`. **The preset alone is
  not that sweep**, and that is the trap: `clang-debug` sets `CMAKE_CXX_CLANG_TIDY=clang-tidy`,
  which on a machine carrying both resolves to whichever `PATH` finds first — 20 in this
  project's WSL image, where 22 sits right beside it as `clang-tidy-22`. So a `clang-debug`
  build reports "clang-tidy clean" in exactly the way that means nothing, and the version it
  used is printed nowhere. Configure a second build directory naming the version, and run that.
- **`CLANG_TOOLS_VERSION` pins a MAJOR, and apt.llvm.org ships rolling SNAPSHOTS under
  one version number** — so the bullet above bites between two binaries that both call
  themselves 22.1.8. `clang-tidy-22 --version` prints `Ubuntu LLVM version 22.1.8` for
  either; only `dpkg-query -W -f='${Version}\n' clang-tidy-22` distinguishes them, and
  `apt-cache policy clang-tidy-22` says whether a newer one is sitting there already
  configured.

  Measured 2026-09-10, PR #1198: local `1:22.1.8~++20260613092238+e80beda6e255` against
  CI's `1:22.1.8~++20260714014902+ca7933e47d3a`, a month apart. A 19-row aggregate table
  in a new test file drew 19 `modernize-use-designated-initializers` errors in CI and
  **zero** locally — same file, same compile database, the check named explicitly on the
  command line, a canary proving the analyser ran. After
  `apt-get install -y --only-upgrade clang-tidy-22 clang-format-22` the identical pre-fix
  file reported exactly 19 locally. Both directions measured against the same source, so
  the variable is the binary.

  **What makes this expensive is that the remedy reads as already applied.** "Run the
  analyser at the version CI pins" is satisfied, on its face, by having a binary named
  `clang-tidy-22` — and the failure is silent in the direction that gets believed, since
  a clean report is what you were hoping for. It also invalidates every earlier verdict
  in the same session: a sweep that could not see one check could not see any check that
  moved in that month, so the whole changed set is re-swept rather than the one file
  re-checked.

  `clang-format-22` rode the same stream and was equally stale, which is the mirror
  hazard the bullet above names — a newer formatter reformatting code the older one
  accepted. No `llvm.sh` re-run is needed where the apt.llvm.org source is already
  configured; `apt-get update` surfaces the candidate. **Both tools have since left that
  stream**: the formatter (next bullet) and the analyser (#1404, the bullet on the analyser's
  BUILD below). The measurement above is why.
- **The formatter is ONE exact build — the PyPI clang-format release `.clang-format-version`
  declares — and a clang-format that is not that build does not write.** Found (#1349) as the
  contour-workflows format-on-edit hook running `clang-format -i` on every C++ edit with the
  first binary on `PATH` — Visual Studio's 22.1.3, against the 22.1.8 snapshot `Check C++
  style` then installed from apt.llvm.org — which is the `-i`-at-another-version rule below,
  automated and invisible.

  **The first remedy declared the snapshot and was replaced before it merged**, and why is
  the rule: a declaration of a build CI does not control is a statement about a mirror.
  `CLANG_TOOLS_VERSION` pins a major and apt.llvm.org rolls snapshots under it, so every pull
  request would have gone red at the next snapshot for a reason unrelated to its change, and
  every developer machine would have had to chase the mirror to format at all. A PyPI release
  is one build with one banner, `clang-format version 22.1.8`, installable natively on Linux,
  macOS and Windows. So:

  - **`.clang-format-version` is the ONE statement of the version (#1407).** It first shipped
    beside a `CLANG_FORMAT_VERSION` in `build.yml` that a ctest held equal to it — two copies
    kept in step, where the analyser's `.clang-tidy-version` had one. So the workflow now asks
    `check-clang-format-version.sh --requirement` for `clang-format==X.Y.Z`, derived from the
    banner. `ctest -R clang-format-version` holds the file to exactly ONE build, spelled as a
    bare release banner `clang-format version X.Y.Z` — a second build is one the hook would
    WRITE with, and a vendor prefix or build suffix names a build no installer can ask for —
    whose major is `CLANG_TOOLS_VERSION`, the same hold `.clang-tidy-version` has, so the
    formatter cannot be left behind by a toolchain bump. `binary:` lines stay legal: the
    grammar is the hook's, and this check is only ever stricter than it.
  - `Check C++ style` installs that requirement into a venv (the runner's python is
    externally-managed) and asserts it is the declared build BEFORE formatting.
  - Which binary is **one resolver**, `check-clang-format-version.sh --resolve`:
    `PACE_CLANG_FORMAT` when set — the only candidate then, refused rather than stepped
    over when it is not the declared build — else the declared build among EVERY clang-format
    on `PATH`, as the hook resolves. `Check C++ style`, `local-gate.sh` and the windows.h check
    all format through it; none keeps a `clang-format-$V` of its own. With none present the gate
    REFUSES before `-i` and prints the install commands; the windows.h check skips. There is no
    default install site, unlike the analyser's: the hook never takes a path, so a second
    resolution rule would let the gate format where the hook refuses.
  - **The banner is identity enough for a formatter**, where the analyser needs its wheel's
    RECORD: a bare release banner is printed by builds of that release tag, and a formatter
    resolves no resource headers relative to itself, so the copied-binary hazard has no
    formatter counterpart.
  - The banner is compared WHOLE. Two builds of one release number are different formatters:
    the apt snapshot prints `Ubuntu clang-format version 22.1.8 (++20260714014902+…)`, so it is
    refused exactly like the IDE's 22.1.3.
  - **clang-tidy is a build of its own**, declared in `.clang-tidy-version` and identified by its
    wheel rather than its banner: the next bullet (#1404).

  **Measured 2026-09-14 on master `ce7c565d`, on this Windows host and its WSL image:** PyPI's
  22.1.8 prints `clang-format version 22.1.8` from both the Windows and the manylinux wheel,
  and passes `--dry-run --Werror` over all 950 tracked C++ files, as the apt snapshot and VS
  22.1.3 also did — so no build disagreed about THAT tree, which is a statement about one tree
  and not about the builds. **And on `a96e4e45`, over all 778 tracked first-party C++ files**
  (`git ls-files '*.cpp' '*.hpp' '*.h'` outside `vendor/`), as they are and with leading
  whitespace stripped and space runs collapsed: the manylinux wheel against the apt snapshot
  (`ca7933e47d3a`, which is the `llvmorg-22.1.8` tag commit) 778/778 byte-identical both ways,
  and the manylinux wheel against the win_amd64 wheel 778/778 identical both ways, raw bytes.
  Controls: every output non-empty, every run exit 0, the as-is output equal to the file for all
  778, and the scrambled output differing from the file for 350, where both builds re-derived the
  same layout. Because the snapshot IS the tag, that shows two builds of one source agreeing —
  it says nothing about the NEXT snapshot, which is the reason for leaving apt, not against it.

  A Windows host now formats natively: `python -m pip install --user clang-format==<release>`
  puts the declared build in the user Scripts directory, which must be on `PATH` for the hook
  to see it. Ubuntu 24.04's python refuses `pip install --user` (PEP 668), and this repository's
  WSL image has neither pip nor venv, so there the route is `pipx`, a venv (apt's `pipx` /
  `python3-venv`), or the wheel another host downloads with `--platform manylinux_2_27_x86_64`,
  unzipped — the resolver's refusal prints each.
- **The analyser's BUILD is `.clang-tidy-version`: an exact PyPI release, identified by its
  wheel, never by a name or a banner (#1404).** The formatter's remedy does not transfer:
  `clang-tidy-22 --version` prints `Ubuntu LLVM version 22.1.8` for every apt snapshot, so there
  is no banner to compare, and `dpkg-query` can tell snapshots apart but not pin one — apt.llvm.org
  keeps only the newest, so a dpkg pin turns every mirror roll into a red on every branch that no
  developer can ever install back. PyPI's `clang-tidy` release is immutable, installs on Linux,
  macOS and Windows, and is the same analyser on all three, which also ended `clang-tidy-windows`
  judging with 22.1.0 while Linux judged with a 22.1.8 snapshot.
  - **A binary IS the declared build when its wheel says so, and not otherwise**:
    - it sits at `<site>/clang_tidy/data/bin/clang-tidy[.exe]`;
    - exactly one `clang_tidy-*.dist-info` beside it has `Version:` equal to the declaration;
    - that dist-info's RECORD holds the binary's sha256.
    `scripts/check-clang-tidy-version.sh --installed` decides it. Anything else — apt's,
    choco's, pip's PATH shim, a copied binary — is UNIDENTIFIABLE, a refusal of its own.
  - **The layout clause is not decoration.** The wheel's own bytes copied out of its tree pass the
    digest and the version and still analyse nothing: measured 2026-09-14, the copy reports
    `'stddef.h' file not found`, because clang-tidy resolves its resource headers relative to itself.
  - **Measured before switching, and the measurement could not see a crash.** Both analysers used
    one apt-generated compile database: the 22.1.8 wheel against the apt snapshot CI installed
    (`1:22.1.8~++20260714014902+ca7933e47d3a`).
    - Under `.clang-tidy`, 304 enabled checks each, no difference.
    - Every check both carry switched on, over 25 sampled units: 14711 diagnostic lines per side,
      identical. The same 25 units under `.clang-tidy` alone were all CLEAN on both sides, which
      could not have shown a difference.
    - **Both comparisons read diagnostic LINES and never the exit status**, and a crashing analyser
      prints no diagnostic line, so it scores as clean. On `a96e4e45` the gate was the real evidence,
      because it builds every unit through the analyser and fails on its status. On the next master
      the wheel segfaulted on a unit #1392 added, where apt, built from the same commit, exited 0.
  - **A crash the declared build is KNOWN to have is a row of
    `scripts/check-clang-tidy-known-defects.sh`, never a disabled check.** The tree names the
    offending value first at every site, with a ONE-line comment naming the check and the issue
    that documents the defect, and each row plants the crashing shape, a named control and a unit the check reports.
    Both CI jobs and the gate run `--installed` against the identified build, so the release that
    fixes the defect goes red there and says what the change must remove. apt's silence on the same
    shape is a null pointer read by luck, and it is not a reason to prefer apt: a crash fails CLOSED.
    **A row is its own record, so it needs no open issue:** it fires on the one event the defect
    waits for, going red on the change that moves the pin and LISTING the site comments to delete,
    so an issue held open for that event is a second, unwired copy of the tripwire. The issue a row
    names DOCUMENTS the defect, open or closed (#1410), and an EMPTY table passes every mode, so
    retiring the last row leaves a working guard.
  - **One question, three askers.** `--resolve` hands a local run the binary `PACE_CLANG_TIDY`
    names, or the one installed at `${XDG_DATA_HOME:-~/.local/share}/pace/clang-tidy/<version>`,
    only after identifying it, and names the exact `pip install --target` command when it cannot.
    `local-gate.sh` passes that binary to the configure. `tidy-sweep.sh` resolves or checks its
    `TIDY` the same way. Both CI jobs install with `--requirement` and check with `--installed`
    before the sweep. There is no fallback to a `clang-tidy` on `PATH` anywhere: that is the
    analyser nothing can identify.
  - **The COMPILERS stay where they were.** The build legs use apt's clang, and the Windows
    database uses choco's `clang-cl`, now at the declared release. The analyser brings its own
    frontend and resource headers.
  - `.clang-tidy-version` is a `SweepEverythingWhen` row, because a new analyser can report in any
    unit. `ctest -R clang-tidy-version` holds its major to `CLANG_TOOLS_VERSION`.
- **A script that NAMES a tool version must name it everywhere that version matters, and
  the gate that says so had the defect it documents.** `local-gate.sh` resolved
  `clang-format-$V` by name, and then let the `clang-debug` preset take its analyser from
  `PATH` -- with the paragraph above written in its own header, four lines from the code that
  ignored it. An argument carried one call short is the shape to look for: the reasoning is
  present, correct, and applied to one of the two tools it was written about. The gate now
  resolves the analyser to an absolute path, **before anything is built** -- since #1404 the
  declared BUILD through `check-clang-tidy-version.sh --resolve`, not `clang-tidy-$V` -- refuses by name
  when it is absent rather than falling back, passes it to the configure, and prints which
  binary it used -- and none of that is loosened by `--no-format`, which names the other tool.
  - **A cached `find_program` result outlives every reason it was chosen**, so the pin has to
    be checked against the build directory and not only passed to it. `find_program` never
    revisits a filled cache entry, and the gate configured only when `CMakeCache.txt` was
    ABSENT -- so a tree kept whichever `clang-tidy` it first found forever, and **re-running
    the gate could not repair it, because re-running the gate is what skipped the configure.**
    Measured on this repository's own WSL image: a `clang-debug` directory the gate itself had
    created sat on `CLANG_TIDY_EXE:FILEPATH=/usr/bin/clang-tidy`, which is 20, while every run
    reported clean. The same shape as the stale `PACE_CC-NOTFOUND` that kept build trees
    on sccache silently, and `CLANG_TIDY_EXE-NOTFOUND` is that shape exactly -- a value, which
    compares unequal, never an absence to be tolerated.
  - **`cmake/portable/ClangTidy.cmake` needs no change and must not get one.** It stays
    generic and droppable into other repositories, and a pre-set `CLANG_TIDY_EXE` cache entry
    already short-circuits its `find_program` -- verified, on a fresh directory and over an
    existing entry, rather than assumed. `-D` on the configure line is the whole mechanism.
  - **The gate tidies ONE of its two presets**, because `ENABLE_TIDY` is on in `clang-debug`
    and off in `gcc-release`. That is a fact a reader would otherwise infer from the absence
    of an argument, so it is a column of the script's preset table and a run prints it.
  - `ctest -R local-gate-selftest` drives the decision against synthetic CMake caches -- a
    directory on the wrong analyser, one that never found any, one with no entry, one already
    correct -- because the gate itself builds two whole configurations and cannot be a test,
    while the part that can be silently wrong is pure.
- **A gate that stops at the first red leg must SAY what it skipped, or stopping early
  becomes a lie.** `local-gate.sh` fails fast, which is correct -- forcing a full second
  configuration after a known failure makes the gate something people stop running, and
  the script's own header already names that hazard. What was wrong is that the refusal
  was the *whole* report: `GATE FAILED: clang-debug tests` and nothing else, so the
  reader supplied "and the rest passed" from optimism. It had not been asked
  ([#501](https://github.com/LASTRADA-Software/pace/issues/501)).

  Measured in #493: gate runs 1, 3, 4, 5 and 7 all failed inside `clang-debug` and
  **none of them reached `gcc-release`**, while a GCC-only
  `-Werror=maybe-uninitialized` -- raised by GCC 14 at `-O3` inlining a ternary into
  `<optional>`'s own `operator!=`, and emitted by clang at no optimisation level and by
  MSVC not at all -- sat in the tree through every one of them. That is almost
  word-for-word the case the script's header gives as the reason `gcc-release` exists.
  It surfaced only because a developer treated an unrun leg as *unrun* rather than as
  covered.

  So **every** run now ends with a per-leg verdict -- `passed`, `FAILED`, or `NOT RUN`
  with the words "has reported NOTHING" -- on the green path too, because a summary
  that appears only on failure is one nobody has read when it matters. Three
  consequences worth keeping:
  - **The renderer is pure**, taking `preset=state` pairs as arguments. The defect was
    a REPORTING defect, and a report that can only be exercised by building two whole
    configurations is the same defect one level up. `ctest -R local-gate-selftest`
    drives every verdict in milliseconds, including the inequality the acceptance
    actually turns on: `FAILED` and `NOT RUN` for one preset must never coincide.

    **This is the same move `node-scratch-isolation-e2e` needed, and it is now the
    standing answer for an instrument whose own defect is invisible.** That fixture's
    verdict logic could only be reached by running the expensive thing it wrapped;
    splitting the DECISION out as a pure function over a record and leaving
    acquisition alone took it from 53 seconds and a `RUN_SERIAL` to 0.3 seconds and
    neither, and made every branch cheap enough to mutate one at a time
    (`.agent/rules/testing.md`). At least four instruments here have had that shape.
    When a gate, fixture or classifier cannot be tested without paying for what it
    measures, split the decision from the acquisition rather than accepting that the
    instrument is untestable.
  - **An unrecognised state renders as unrecognised.** A fourth state arriving at the
    default arm as `passed` would recreate the bug exactly, one level down. Skipped,
    absent, unstarted and failed are four states here as everywhere.
  - **The states are derived from the preset table**, and the green line no longer
    spells "(clang-debug + gcc-release)" as a literal -- a third row would have been
    silently missing from the gate's own statement of what it had just done.

  Reading a red log is the same trap once more: ninja prints `FAILED:` and puts the
  error text several lines BELOW it, so a wrapper filtering on `error|warning:` alone
  surfaced an unrelated zstd warning and none of the actual failure. **A filter that
  reports nothing and a run that found nothing render identically.** Read the raw log
  the message names, or filter on `FAILED:` as well.

- **A run that never concluded is the fifth state, and a trap cannot report it here.**
  The verdict came from `fail()` and from the green path, and NEITHER runs when the
  process is killed -- so a run terminated by a signal ended with no `GATE FAILED`, no
  `LOCAL GATE PASSED` and, after #501, no leg block either. The only thing separating
  it from a completed run was the ABSENCE of both lines, and absence is equally what a
  scrolled-past line, a truncated log and a lost terminal look like
  ([#584](https://github.com/LASTRADA-Software/pace/issues/584)). It is not
  hypothetical: every lane on a shared machine runs these script names out of different
  worktrees, so a name-matched `pkill -f local-gate.sh` in one lane hits every other
  lane's run -- the worktree path appears nowhere in the pattern. Twice in one night.

  **The trap route was measured and rejected, and the measurement is the entry.** Bash
  defers a TRAPPED signal until the running foreground command returns, and this gate's
  foreground commands are `cmake`, `ninja` and `ctest`. On bash 5.3, a SIGTERM sent at
  **t=2s** into a 6s foreground command ran the handler at **t=6s** -- a trap that fires
  only after `ninja` finishes is close to no trap at all. The standard workaround,
  backgrounding the command and `wait`ing for it, does fire immediately (**t=2s**,
  measured) and is **worse**: the child is orphaned and reparented, so the gate would
  print a tidy `did-not-conclude` while leaving `ninja` still writing into the build
  directory. Measured on a real killed run of this gate mid-build-leg: **34 descendant
  processes** left alive under the worktree, which had to be cleaned up by matching
  `/proc/<pid>/cwd`. A developer's re-run then races an orphaned build in the same
  `binaryDir` -- the two-gates-in-one-build-directory defect already listed above. So
  the deferral is not a detail to work around; it is the argument for the other route.

  The route is a **start marker plus a rule**, and the rule is: *a log with a start
  marker and no terminal line DID NOT CONCLUDE -- re-run it, never interpret it, and
  never read it as a red gate.* `did-not-conclude` is a distinct outcome from `failed`
  because they are fixed in different places: one is somebody else's `pkill`, the other
  is your code. Four things make that more than prose:
  - **The marker names its own subject** -- pid, worktree and commit. A verdict that
    does not say what it is a verdict about has already cost a run here, when a `/tmp`
    wipe left one gate's log where another's goes and it reported a failure that was
    already fixed. The pid is there because the cause is a name-matched kill, and the
    tree because that is the field such a kill does not look at.
  - **The rule is a function, not prose**: `local-gate.sh --classify=<log>` answers one
    word per row of the script's `gate_outcomes` table, each with an exit status of its
    own, so the tooling around a run can tell. The rows are deliberately not listed here:
    this sentence named four of them while the table held six, and a stale list reads as
    complete. Pure -- log text in, one word out
    -- which is the standing answer above applied once more. `passed` and `failed` keep
    the gate's own `0` and `1`; `2` is skipped because it is the script's USAGE status,
    and `--classify=$LOG` with an unset `LOG` lands there -- a caller reading only the
    status would take *you typed that wrong* for *the run was killed*. Those two are not
    commensurable, so the self-test asserts no outcome sits on it, and the constant is
    defined once and read by both the argument loop and the table rather than spelled
    twice.
  - **The LAST marker wins, and a terminal line counts only after one.** A log file
    gets reused, so a green run followed by a killed one is `did-not-conclude`, which
    `grep -c PASSED` gets backwards; and a terminal line with no marker before it is
    `no-gate-run` rather than the verdict it resembles, because it cannot be attributed
    to a run the log can show. Both escalate not-knowing to *re-run it*, which is the
    only direction that cannot silently vouch for a tree.
  - **Capture both streams.** The failure line goes to stderr and the pass line to
    stdout, so a log holding one of them can answer half the question.

  Watched refusing, which for this one takes two forms because the mechanism has two
  halves. The classifier: four breaks -- `did-not-conclude` given `failed`'s status, the
  first marker winning instead of the last, substring matching instead of line-anchored,
  and a terminal line counting with no marker before it -- each reddened a named case.
  The marker: a **real** SIGTERM to a **real** run mid-build-leg, by pid and never by
  name match, which exited 143, left a log with a start marker and zero terminal lines,
  and classified `did-not-conclude` at exit 3. A start-marker scheme never interrupted
  is untested in the only case it exists for.

  And the self-test gained a `N checks ran, M failed` line in the same change, because
  without it none of the four breaks above could be believed: `expect` is silent when
  it passes, so a run that died half way through is indistinguishable from one where
  everything passed, and *no failures printed* reads as *the guard did not fire*. That
  is this ticket's own confusion one level down. It immediately earned itself -- one of
  the new checks claimed to assert that `did-not-conclude` and `failed` have different
  exit statuses and actually compared whole table ROWS, whose sentences differ whatever
  the statuses do. It read green for exactly the collapse it names, and only watching it
  fail to fire found it. **A signal that cannot be false in the failing case is not
  evidence**, and a check is not evidence that it fires until it has been seen to.

- **A green CI run under an active compiler cache proves the objects LINK, not that
  the sources compile** — CI runs cached on every leg, and no leg builds cache-off.
  So a `-Werror` defect in a translation unit whose object is replayed passes every
  required context. That window is real and nothing closes it today.
  **But it was not the mechanism the one time it was blamed, and the correction is
  the more useful half.** A dead function template lived on master through full CI
  (#539, #540) and the cache was the obvious suspect. Measured instead: the project
  enabled `-Wunused-template` NOWHERE — neither `-Wall` nor `-Wextra` implies it —
  so an UNCACHED build of that commit would have failed nothing either, and
  clang-tidy did not catch it under this tree's `.clang-tidy`. Verified against the
  exact `-W` set the compile database records, with a control: the same flags reject
  an unused *variable*, so the set was live and `-Werror` was on. The flag is now
  added and the whole tree builds clean under it. **Reach for the cache last**: it is
  the explanation that needs no evidence, which is exactly why it wants some.

- **A reference build passes `-DUSE_COMPILER_CACHE=OFF`, and the gate is a reference build.**
  `local-gate.sh` invoked `cmake --preset` without it, and `USE_COMPILER_CACHE` defaults to ON,
  so both its configurations were fronted by whichever launcher happened to be installed, at
  whatever version, with no check and no mention. Measured: 148 `LAUNCHER = ` lines in
  `clang-debug` and 618 in `gcc-release`, all pointing at an installed `pace-cc` hundreds
  of commits behind master and subject to [#368](https://github.com/LASTRADA-Software/pace/issues/368)
  ([#471](https://github.com/LASTRADA-Software/pace/issues/471)).

  **The rule was already standing, in a file sitting beside the one that ignored it.**
  `scripts/launcher-replay-e2e.sh` names "the standing `-DUSE_COMPILER_CACHE=OFF` rule" in its
  own header and records what it is for: in #319 a cache-backed build of a test binary
  segfaulted where the same commit built cache-off passed, and nothing in CI could have
  reported it. `CMakePresets.json` carries the same value on `clang-coverage` for an
  independent reason. The project had decided this twice and written it down twice, and the
  gate was the only reference build in the tree that dissented. **Stating a rule in the file
  that obeys it is how the file that does not obey it never learns about it** -- the same
  mechanism as `tsan-gate.sh` documenting that macOS has no `timeout(1)` while `cluster-e2e.sh`
  called it anyway. A rule with one instance is a comment; a rule with two needs a check.
  That paragraph is gone (#488 replaced the resolver with `run_bounded`), and how it ended is
  the sharper half: it also claimed the `clang-tsan` preset runs on macOS, which it never has,
  so the fallback it justified had never executed anywhere. **What failed to travel was not a
  fact but a plausible sentence** -- which is why the remedy was a shared implementation plus a
  scan (`check-e2e-helpers.sh`), and not a better comment. A reader cannot tell a measured
  sentence from a remembered one, and neither can a reviewer.
  - **Pinning the other two tools is the argument for REMOVING this one, not for versioning
    it.** `clang-format` and `clang-tidy` are pinned because their version changes the verdict
    and there is a canonical version to pin *to*. A compiler cache has neither: no canonical
    version, and it is supposed to be verdict-**neutral**. When it is not, it substitutes an
    object the tree did not produce. The tempting symmetry -- require the launcher to be the
    build of the current tree -- is unsound twice over. `git describe` on a dirty tree yields
    `X.Y.Z-N-gsha-dirty`, and two different working trees produce that same string, so it is
    not an identity; and the only launcher that could ever match is one built from the tree
    under gate, which routes the gate's objects through the very change being gated. That is
    worse than an unknown-vintage launcher, which is at least independent of the diff.
  - **Passing the flag is not the same fact as no launcher being in effect.**
    `cmake/portable/CompileCache.cmake` returns early when `CMAKE_CXX_COMPILER_LAUNCHER` was
    set externally -- a preset, a toolchain file, an older `-D` -- and leaves it untouched. So
    the gate reads the **generated build**: `LAUNCHER = ` in `build.ninja`, which is already
    this project's idiom for the question, since `launcher-replay-e2e.sh` checks the same
    string from the other side to prove a launcher *is* in use. The first design read
    `CMAKE_CXX_COMPILER_LAUNCHER` back out of `CMakeCache.txt` and would have reported "no
    launcher" against both live gate directories: `CompileCache.cmake` sets it as an ordinary
    directory-scope variable and never as a cache entry, so that guard could not fire -- inside
    the fix for a ticket about guards that cannot fire. It was caught by checking the two real
    caches rather than by reasoning about the CMake documentation.
  - **Whatever the refusal reads is also a reason to configure, or the gate cannot repair the
    state it refuses.** CMake enters `-D` values into `CMakeCache.txt` and writes that file
    even when the configure then FAILS, leaving the old `build.ninja` untouched -- so a first
    run can leave a cache reading `OFF` with the right analyser beside a launcher-fronted
    build. Judged from the cache alone, every later run finds nothing to configure, refuses on
    the stale build, and blames an external `CMAKE_CXX_COMPILER_LAUNCHER` that nobody set --
    and re-running can never fix it, because re-running is what skips the configure. That is
    the analyser bug above, reopened one file over. So `configure_reason` reads the generated
    build too, through the same `launcher_verdict` the refusal uses: one observable, not two
    that can disagree, and the refusal's message is then true because the only state that
    reaches it is one that survived a configure which actually ran.
  - A missing `build.ninja` is `unknown`, one that cannot be READ is `unreadable`, and neither
    is ever folded into a count of zero: zero is a reading, the other two are the absence of
    one and the failure to take one. `awk` on a file it cannot open exits **without running
    its `END` block**, so it prints nothing -- and an empty answer reaching the caller's
    default arm renders a failed reading as the worst positive one, refusing a build nobody
    could read while blaming a launcher nobody set. A `[[ -f ]]` that passes for a file whose
    permissions deny it is exactly where the fourth state hides. `USE_COMPILER_CACHE` absent
    reads as ON, since that is the option's default.
  - The match is **not** anchored to ninja's two-space indent, deliberately: anchoring fails
    OPEN if that spelling ever changes, because a count of zero reads as a clean build. Loose
    can only over-count, which for a gate is the safe direction -- and since
    `CMAKE_<LANG>_LINKER_LAUNCHER` emits the same binding, the number is reported as
    launcher-fronted **edges** rather than as compile edges.
  - **The gate does not own its build directories, and says so.** Every preset has one
    `binaryDir`, `out/build/${presetName}`, and these are the trees this project tells
    developers and agents to build in; `-D` writes a cache entry and `option()` never
    overrides one, so a gate run turns the compiler cache off there *permanently*. That is
    accepted as a STATED cost -- the run prints what it did, that it is permanent, and how to
    undo it -- and gate-owned directories are
    [#487](https://github.com/LASTRADA-Software/pace/issues/487). A silent change to how
    a tree builds is the defect this whole entry is about, so the fix for it must not commit a
    quieter version of it one directory over.
  - The one-time cost is stated by the run that incurs it. Dropping the launcher rewrites every
    compile command, so ninja rebuilds the configuration from scratch once; a developer
    watching that with no explanation files it as breakage. An explained cost is a cost.
  - **What it costs, measured rather than asserted** -- and as a table of conditions, because a
    single number here is the wrong quantity in whichever direction it is quoted. One
    `gcc-release` configuration, 630 object edges, from scratch, 32 jobs, WSL2 on a 9p mount:

    <!-- table-total: none -->
    | leg | wall clock |
    |---|---|
    | launcher on, nothing stored yet (629 fronted edges) | 224 s |
    | **launcher off** (0 fronted edges) | **230 s** |
    | launcher on, everything replayed | 94 s |

    So a **full** rebuild of one configuration costs ~136 s more, about 2.4x -- and a MISSING
    cache costs the same as no cache, which is why the first row must not be quoted as the
    price of this change. Neither may the third: the gate is incremental, so a from-scratch
    build happens once when this lands, and thereafter only when something invalidates
    everything anyway. Note also that the warm row is exactly the exposure -- 629 objects
    replayed from an earlier build is the state in which "the objects need not match this tree"
    is a live claim rather than a theoretical one.
- **When `clang-debug` cannot be built, get the sanitizer from GCC instead.** That
  preset is the only one that runs ASan, and on a host where it cannot configure at
  all the tempting conclusion is that no sanitizer coverage is available locally. It
  is: GCC has ASan too, and a throwaway tree costs one configure.

  ```sh
  cmake -S . -B out/build/gcc-asan -G Ninja -DCMAKE_BUILD_TYPE=Debug \
        -DCMAKE_CXX_FLAGS="-fsanitize=address -fno-omit-frame-pointer" \
        -DCMAKE_EXE_LINKER_FLAGS="-fsanitize=address" \
        -DPACE_ENABLE_TLS=ON -DPEDANTIC_COMPILER_WERROR=OFF
  ```

  **ASan only, never `address,undefined`.** UBSan's instrumentation defeats GCC's
  constant evaluation of the option tables' lambda addresses, so `Options.hpp`'s
  `TableIsWellFormed` `static_assert` stops compiling -- a build error with nothing
  to do with the code under test, and an easy reason to abandon the idea.

  A use-after-free reached CI through two jobs while this was thought unavailable.
  The local run that catches it takes about a minute.

- **A memory bug reports only if something disturbs the freed block, so run the
  WHOLE suite.** The case that failed in CI passes under ASan on its own: nothing
  reuses the allocation, so nothing is read across a boundary the interceptors
  watch, and the test reports success. The same held for a standalone repro --
  decode, read, nothing in between: clean; sixty allocations inserted between the
  two: `heap-use-after-free` immediately. A quiet sanitizer run on one test is not
  evidence that a diagnosis is wrong.

- **After reverting files to reproduce a bug, check that the build SUCCEEDED.**
  Reverting two files to the parent commit left an unrelated translation unit
  failing to compile; ninja stopped, and the binary that ran was the *previous* one.
  It passed, which looked like proof the bug was not real. `ninja: build stopped`
  scrolls past above a green test run, and a reproduction that did not rebuild is
  not a reproduction.

- **A sanitizer that is on in the cache is not a sanitizer that is on in the build.**
  `cmake/portable/Sanitizers.cmake` initialised `SANITIZER_COMPILE_OPTIONS` to `""`
  as a normal variable, published the real flags through
  `set(... CACHE INTERNAL ...)`, and then `list(APPEND)`ed one more flag to the same
  name. Under **CMP0126 NEW** -- which `cmake_minimum_required(3.28)` selects -- a
  cache `set` no longer removes a normal variable of that name, so the empty one
  keeps shadowing the cache. The append therefore starts from nothing and
  `add_compile_options` receives `-fno-sanitize-recover=undefined` and no
  `-fsanitize=` at all, while `CMakeCache.txt` says
  `ENABLE_SANITIZER_ADDRESS:BOOL=ON` and the configure log prints
  `[Sanitizers] Enabling: address,undefined`. Every signal an author would check says
  yes; not one object is instrumented -- and not on a re-configure, on a **completely
  fresh build directory**, which is what CI makes. So the project's sanitizer gate had
  never run: not locally, and not in the `clang-tidy` job that ends with
  `ctest --preset clang-debug`. Turning it on found a heap-use-after-free in
  `EpollSocket::Close`, a leaked coroutine frame per dial that `IReactor::CancelPending`
  now prevents, and a plain use-after-free in a test fake that had been passing 300
  consecutive runs.
  The flags are assembled in locals and published once now. Two things to keep: the
  check that actually answers the question is `grep -o -- '-fsanitize=[a-z,]*'` **on
  `build.ninja`**, since the cache and the log are precisely the two places that lie;
  and this is the same class as the `USE_COMPILER_CACHE` configure probe -- a tool
  that silently does nothing is worse than one that is off, because the second is
  visible.
  - **A guard written above an existing one can be silently discarded, and it
    disappears from exactly the cases that already needed thinking about.** Adding
    a step-level `if:` to `.github/workflows/build.yml` inserted a second `if:` key
    above three steps that already carried
    `if: startsWith(matrix.preset, 'clang')`. YAML keeps the **last** duplicate key,
    so the new gate evaporated on precisely the conditional steps -- the ones a
    reader is least likely to re-check, because they visibly have a condition. No
    warning from YAML, none from Actions, and the workflow ran. Same family as the
    sanitizer above: the knob reads set, and nothing it names is in effect. Merge
    into one expression (`gate && (original)`) rather than stacking, and scan for
    adjacent `if:` lines afterwards -- `awk` over the file is enough, and it is the
    only thing that distinguishes "gated" from "gated on paper".
  - **So a sanitizer job proves the tree only once something proves the sanitizer.**
    `scripts/tsan-gate.sh` will not report clean until it has answered two separate
    questions, because they fail separately: an **undefined** `__tsan_init` reference
    in each artefact's **own object files** says *this artefact* was instrumented,
    and `src/tests/TsanCanary.cpp` -- a deliberate data race, built by the same
    `add_compile_options` as everything else -- says the runtime still detects and
    reports. A `TSAN_OPTIONS`, a suppressions
    pattern or a stripped runtime can break the second while the first still holds.
    The canary is run **with the suppressions file active**, so a wildcard broad
    enough to swallow an obvious race fails the gate instead of silently disarming
    it. Every refusal has a message of its own, because each is fixed somewhere
    different, and each was verified by making it happen -- the list lives in that
    script's header and deliberately nowhere else. It said "five refusals" in three
    files, in three orders, having dropped the two hardest to reason about: a hard
    count restated beside the thing it counts is a fact with no owner.
  - **`__tsan_init` in a BINARY is a property of the link, not of any translation
    unit** -- so asking `nm --defined-only` of a binary cannot prove instrumentation,
    and for three years that is what this gate did. The symbol is *defined by the
    sanitizer runtime*, which the link pulls in whole whenever `-fsanitize=thread` is
    on the link line. Measured, same source, two objects, two binaries: a canary
    whose TU was compiled with **no sanitizer flag at all** produced a binary
    carrying `__tsan_init` and passed the proof. Ask the **objects** instead, where
    the reference is *undefined* and cannot be borrowed from a runtime the object is
    not linked to. Same symbol; what changed is `--undefined-only` and what it is
    asked of.
    Three things that only appear once you look at where the proof is *used*:
    **the canary was never the exposed artefact.** An uninstrumented canary fails
    closed -- it exits 0, reports no race, and the gate refuses -- though it used to
    do so while blaming `TSAN_OPTIONS`, the suppressions file and the runtime, all
    three of which were fine. The **test binaries** had no backstop: `RunTarget`
    checks the timeout, the tag filter and the assertion count, and not one of those
    distinguishes an instrumented run from an uninstrumented one, so an
    uninstrumented `PaceTest` ran, reported assertions, exited 0, and the gate
    printed *all scoped targets clean*. A fix covering only the canary would have
    closed the issue with its stated harm untouched.
    **The obvious per-function symbols are the wrong ones.** `__tsan_func_entry`,
    `__tsan_read` and `__tsan_write` are emitted per instrumented *function*, so an
    object whose TU has no functions carries none -- six of `PaceTest`'s 135,
    the platform-gated `Iocp*`, `Kqueue*` and `Tls*` files that compile to nothing
    on Linux. They do carry `__tsan_init` and a `tsan.module_ctor`: instrumented,
    with nothing to instrument. A rule built on the hooks needs an empty-TU
    exemption; one built on `__tsan_init` needs none, and holds 185 of 185 objects
    across the three targets. That is the empty-translation-unit state showing up in
    an *instrument* -- naming it rather than collapsing it into pass or fail is the
    four-states rule again.
    **And the guard is exercised**: `ctest -R tsan-gate-selftest` drives the
    instrumentation verdicts against staged object trees -- a suite binary with one
    uninstrumented object first, since that is the half with no backstop -- through a
    stub `nm`, and since #488 drives the BOUND's three outcomes against staged
    executables, which need no object tree at all. Neither half needs a compiler, so
    both run in the default set. A guard that has never been
    seen to fire is what this whole file is about, and this one could not fire at
    all.
  - **A filter that matches nothing is a suite that tested nothing**, and every
    other signal in that run reads clean. The gate names it, and separately refuses
    an exit of 0 that reported no assertions. This is the same shape as a sweep that
    skips files and a `-header-filter` that matches no path: the tool ran, the
    artefact was fine, and *nothing was examined*.
  - **A gate that is red a few percent of the time is disarmed as thoroughly as one
    that was deleted**, and it happens through habit rather than code: people learn
    to re-run it. The TSan canary raced two threads on one `int` and was SILENT --
    the race happened, ThreadSanitizer said nothing -- in a few runs per thousand
    (#473). So the acceptance for a change to `src/tests/TsanCanary.cpp` is a RATE
    over at least a few hundred runs, recorded, and reproducible by whoever next
    doubts it: `scripts/tsan-canary-rate.sh`, which is the deliverable rather than a
    paragraph claiming it was checked. Measured at 5000 runs per arm, the old shape
    was 0.220% silent unpinned and **0.700% pinned to two CPUs** -- the wrong
    direction, since a two-core runner is the machine it has to be certain on.
    The fix is what the numbers said, not what the mechanism suggested. The obvious
    hypothesis -- shadow-cell eviction from hammering one address -- predicts that
    more accesses are worse, and it is refuted: 1 increment each is 2.50% silent, 10
    is 2.80%, 1000 is 0.20%, 100000 is 0.00%. More work on one address is SAFER, and
    a single unsynchronised pair, which is unambiguously a race and which TSan
    decides on happens-before rather than on overlap, is the least reliable shape of
    all. **No mechanism is claimed in the file, deliberately** -- a wrong explanation
    would send the next reader somewhere expensive. What the data shows is which
    dimensions move it: distinct LOCATIONS matter most (1024 touched once each is
    reliable where one touched 1024 times is not), repetition helps but needs orders
    of magnitude more, so the canary uses both with margin in each.
  - **And a figure is a quantity with an UNCERTAINTY.** This is the sibling of *a
    performance figure is a quantity under conditions*
    ([`compile-cache.md`](compile-cache.md)), and it was missing from it: a count
    with no interval attached reads like a measurement and is a hope.
    **Zero is where this is easiest to forget, because zero reads as the absence of
    doubt rather than as a value with an interval around it.** Zero silent runs in
    5000 is not a rate of zero -- the rule of three bounds it at ~0.06% at 95%, so a
    300-run zero-tolerance gate built on that figure expects 0.18 events and would
    fire about **one run in six**: red one time in six to prevent a canary that was
    silent one time in five hundred, which is #473's own failure mode one layer up
    and harder to argue with for looking principled. The converse omission is how
    two honest measurements nearly became one number -- 4/100 silent on one machine
    is P = 7.8e-5 against another's 0.220%, and 5.5e-3 against that machine's harder
    0.700%, so the samples disagree about the MACHINES rather than about the rate
    and both rows stand. Attach the interval, and say what it is an interval on --
    "P is small" without naming the hypothesis it is small under is the same
    omission wearing a number.
  - **A flag combination that cannot express the question still returns an answer.**
    The species `pkill -f`, `grep -c` read as a position and `grep -q` under
    `pipefail` all belong to: **the shell obliges regardless, and none of them
    errors.** The cleanest specimen is `grep -Lq`, where the contradiction is
    INTERNAL — `-L` lists files WITHOUT a match, `-q` suppresses output and exits at
    the first match, and the two cannot both be honoured. Instead of complaining it
    picks one, and it named two files as lacking a symbol they contain.

    Three things make that the worst of the family, and the second is the one to lead
    with.

    **It was a POSITIVE CONTROL** — the instrument added specifically to stop a wrong
    conclusion. A broken control is worse than no control, because its presence is
    what licenses the confidence. And it generalises past shells: **a control is the
    one instrument nobody checks, because checking it is what it was for.** Anybody
    instructing a team to add positive controls owes them that caveat.

    **Its error pointed at refuting a claim**, which is the direction that gets acted
    on — *because refuting feels like diligence*. It was one step from a correct rule
    being reported as overstated.

    **And nothing about the output looked wrong.** Two files is a plausible answer;
    unlike a wrapped message or an empty capture there is no tell. The only defence is
    re-deriving the control by a different construction — here an explicit loop, which
    gave **0 files lacking it** and turned "consistent with" into "confirmed".
  - **`producer | grep -q` is a false NEGATIVE under `set -o pipefail`, and it fails
    on the SUCCESS path.** `grep -q` exits the instant it matches, which closes the
    pipe; the producer is killed by SIGPIPE; `pipefail` then takes the producer's
    status and the pipeline reports failure. So `nm "$bin" | grep -q __tsan_init`
    says "no such symbol" precisely *because* the symbol was there. Capture the
    output into a variable and match afterwards
    (`syms="$(nm "$obj")"; [[ "$syms" == *__tsan_init* ]]`), or drop `-q`. This is
    not specific to `nm`: **every "does this artefact contain X" idiom in this tree
    is exposed to it** -- symbol checks, `strings | grep -q`, `objdump | grep -q`,
    any long producer feeding an early-exiting matcher. It bit `scripts/tsan-gate.sh`
    itself, which is the script written to catch exactly this class of thing, and
    that is the first time here that the *checking mechanism* produced the false
    reading rather than the thing being checked.
    **And it is worse than a false negative: it is RACY.** Measured while fixing
    #472, in the census scripts written to count instrumented objects. Whether
    `printf` finishes before `grep -q` closes the pipe is a scheduling accident, so
    two runs over the same 135 objects returned **129 and 108**, and a listing built
    the same way named **27** offenders against a true **6**. A deterministic wrong
    answer is caught by the first person who checks it twice; a racy one is
    attributed to the subject, which is how it survives. Two runs agreeing is
    therefore not evidence that a pipeline of this shape is sound.

    **And it came back, in EIGHTEEN sites across twelve scripts, with the rule already
    written down here** ([#970](https://github.com/LASTRADA-Software/pace/issues/970)).
    Observed as `clang-asan-ubsan` failing `check-tidy-blind-spots-selftest` with a
    message saying it could not find a phrase that was in the evidence it printed
    directly beneath — which is not a contradiction but the diagnosis: the match never
    failed, the pipeline's STATUS did. It reddens correct branches, intermittently, and
    a re-run clears it, which is the shape #473 records as teaching people to re-run
    until a gate is disarmed.
    - **And its mirror on the other side of the same pipe: a `<<<` operand of 64 KiB
      or more DEADLOCKS on Git Bash.** bash writes a herestring into a PIPE in full
      before it starts the reader, so past the 64 KiB buffer the write blocks with
      nothing draining it. Measured on `bash 5.2.37(1)-release` to the byte -- 65535
      completes, **65536 hangs** -- and it is SIZE rather than content: this
      repository's own tracked-file listing PADDED past the boundary hangs 5/5, and the
      larger one TRUNCATED below it hangs 0/5. A first probe over synthetic data said
      65540 hung while 66000 and 70000 passed, which fits no mechanism and was one
      sample per size; the arms have to be the real idiom over the real data.
    - **The margin was 508 bytes.** `_third_party_select` takes the WHOLE listing and is
      what every tracked-file enumerator reaches through; master's listing was 65028
      bytes when this was found, so the next handful of tracked files would have hung
      all of them, on Windows and nowhere else, whoever added them. A branch adding
      sixteen got there first, and **the runner was ruled out before the tree**: the
      suite's total was 583.63 s against 593.45 s and 576.26 s on passing runs of the
      same leg, with 5260 of 5282 tests normal. **The two that timed out take 2.5 s and
      5.5 s -- they were not slow, they were deadlocked, and raising a `TIMEOUT` would
      have buried it** (#1515). The remedy THEN was process substitution, whose reader
      drains concurrently and which still reports `grep`'s own status rather than a
      producer's: `< <(printf '%s\n' "$x")` -- **superseded below for an EXTERNAL
      reader**, and kept only where the SHELL reads. The audit of the sites still under
      the boundary, and the scan that should refuse the next one, are
      [#1591](https://github.com/LASTRADA-Software/pace/issues/1591).
    - **And process substitution was itself the next defect, for an EXTERNAL reader.**
      `grep < <(printf ...)` makes grep the PARENT of the writer, and on a GitHub Windows
      runner such a grep came back **exit 148** in round 10, in `header_filter_taken_lines`:
      128 + 20, where 20 is **SIGCHLD** in the MSYS2 runtime (`cygwin/signal.h`; `kill -l 20` says
      CHLD), not Linux's SIGTSTP. That the writer's exit is what killed it is INFERRED:
      neither the micro shape nor the real path reproduced locally, under load, on Git for
      Windows 2.51 (MSYS 3.6.5, bash 5.2) or 2.55 (MSYS 3.6.10, bash 5.3, the runner's)
      ([#1630](https://github.com/LASTRADA-Software/pace/issues/1630)). Round 8,
      in `_third_party_select`, was a **status-2 refusal** whose grep status was never
      printed; it was READ as a kill and was not measured as one, so it is not a second
      instance.
    - The parentage is MEASURED, each writer reading its own PPID out of `/proc`, on Git
      Bash 5.2.37 and on bash 3.2.57. The filter is the writer's parent for `cmd < <(w)`
      and `$(cmd < <(w))`, **and for an ARGUMENT `cmd <(w)` inside `$( )` or a
      pipeline** -- the `diff <(a) <(b) | sed` and `$(comm -23 <(a) <(b))` this tree had
      eight of, two of them deciding a verdict with comm's status unread. A top-level
      `cmd <(w)` is a sibling, and `done < <(cmd <(w))` is a parent on 5.2 and a sibling on
      3.2: **safety that depends on the construct around a line and on the bash version is
      not a property a line can show**, so the rule is the one it can -- no external filter
      reads a process substitution, in either position.
    - What does not depend on the inference: in a PIPE the writer is the child of the shell
      running the pipeline in every context measured, it drains concurrently, and
      `PIPESTATUS[1]` is the filter's status even under `pipefail`. So an external filter is
      fed through `pipe_lines_into`, or `pipe_pair_into` for a two-input `comm`/`diff`
      (`/dev/fd/3` and `-`), both in `scripts/lib/third-party-roots.sh`; a `while read` loop
      or a shell function is the SHELL reading, and stays on `< <(...)`.
      `procsub-reader-scan` in `check-e2e-helpers.sh` refuses both shapes, reading the
      arguments QUOTE-AWARE and allowing the prefixes a command carries (`VAR=x`,
      `timeout N`, `nice`, `stdbuf`, `time`, `command`, `env`, a backtick), and names its
      blind spots, all failing OPEN: a filter off its list, or behind a wrapper off the
      prefix list (`ionice`, `sudo`); one invoked through a variable; a `<(` on a
      continuation line; a quoted argument holding an escaped quote of its own kind, and
      any quoting it does not model (`$'...'`, nested `$( )`); and the `run:` blocks of
      `.github/workflows`, which it does not walk; and a file its own grep failed on
      ([#1631](https://github.com/LASTRADA-Software/pace/issues/1631)). Its own canary lines sit
      in a `procsub-scan` data REGION around the two heredocs alone, so
      `check-e2e-helpers.sh` is scanned like any other file rather than exempted whole.
    - **The status, once read, has to carry WHOSE failure it is.** Round 10's red was
      `status 1 and [uncovered ]`: `Judge` read the coverage without its status, so a killed
      grep blamed the filter. Fixing that with one status for every refusal would have blamed
      the CHECK for a filter that does not compile, the other half of f6511b92b. So the
      classifiers refuse with `HeaderFilterDoesNotCompile` (3) or `HeaderFilterCheckFailed`
      (2), and both consumers name them through one `header_filter_refusal`.
    - So it is a **SCAN** now, in `check-e2e-helpers.sh` beside the `timeout` and
      bash-3.2 ones, off the same `_shell_scripts` enumeration. Five scripts already
      carried a comment explaining why they do NOT do this, and it spread anyway:
      *a rule stated in the files that obey it never reaches the file that does not*,
      which is #627 in a different costume.
    - It examines only scripts that actually `set` pipefail, not ones that MENTION it —
      those five comments are exactly the text a looser predicate would fire on, and
      spending a scan's credibility on rows that are already right is how it gets
      ignored. The predicate has a canary of its own, because it decides which files are
      examined AT ALL: read wrong in the quiet direction it exempts everything and the
      scan reports clean over nothing.
    - **The hand census that opened the ticket missed five of the eighteen**, and they
      were the worst five: `check-gated-jobs.sh` and `check-merge-queue-contexts.sh`,
      the two checks that decide which contexts are REQUIRED. It spelled the pattern
      `| grep -q` and the real spelling was `grep -Fxq`. A pattern is narrower than its
      author reads it as — the mirror of `pkill -f` being broader — and it is the SCAN
      that found them, not the person who wrote the ticket.
      **And that ticket's own header said "11 sites, 10 files" over a table listing
      13** — a total stated beside a table rather than derived from it, which is the
      rule two sections down, broken in the act of reporting a broken rule. The final
      figures here are computed from the diff, not typed.
    - The remedy is a HERESTRING, `grep -q P <<< "$text"`: no pipe, so no SIGPIPE, and
      no capture-and-compare boilerplate at the site. Capture-then-match stays right for
      a producer that is a COMMAND rather than a variable.
    - What the scan cannot see, stated rather than left to be found: a `| grep -q`
      inside a double-quoted STRING runs nothing, and no regex over the defect's own
      shape can tell. The `timeout` scan escapes that by demanding command position;
      there is no equivalent here. Such a line is reworded or the file is exempted with
      a reason. None exists today.
    - **THE CONSUMER IS NOT THE POINT; LEAVING EARLY IS — and #970 closed a SPELLING
      while the scan then enumerated ONE consumer.** `head -N` returns after N lines
      for the identical reason, and so do `grep -m N` and a `sed` script carrying `q`.
      So the scan was exact about `grep -q` and silent about every other one: *a list
      is silent about what it does not name* (#492), rebuilt inside the instrument
      written to replace a list. `check-script-modes.sh` exited **141** under MSYS2
      bash, deterministically and with no output at all, on
      `mode=$(printf '%s\n' "$out" | head -1)` under `set -euo pipefail` — an
      instrument failing, not a verdict — and the `grep -q` scan read the file clean
      (#1111). The scan covers all four shapes now, over the same file set and with the
      same two-direction canary (#1181). Two of the four have no site in this tree at
      all today: `sed`'s `q` and `grep -m` are covered before they arrive, which is
      the whole difference between a scan and a list.
      - **32 sites in 14 files**, remediated with the scan. #1181 estimated *~30
        across 14 scripts*; the figure here is the one the scan and an independent
        census both produced, on this tree, at the commit that closed it — and it is a
        count of the SHAPE, not of defects: the hazard bites only where the payload can
        exceed the pipe buffer AND the pipeline's status is consulted.
      - The `set -e` half is load-bearing, and a probe missing it EXONERATES the code:
        without `-e` the pipeline's 141 is not fatal and the script exits 0. #1111
        records two such reproductions, both of which refuted the right answer.
      - Size decides whether it bites at all, so a small fixture reports the idiom
        working. Measured by #1181 on the reporter's box, 200 runs per size,
        `printf '%s\n' "$big" | head -1` under `set -uo pipefail`: **0 of 200** nonzero
        at 13,892 bytes, **200 of 200** at 211,893 bytes. The boundary is the 64 KB
        pipe buffer — while the whole payload fits, the producer's `write()` completes
        before the consumer leaves. Same shape as the `grep -q` figures above, from a
        different reporter on a different day.
      - `head` reading a FILE is not this and must stay unmatched: `head -1 "$path"`
        has no pipe. A scan that fired on it would refuse correct code, which is how a
        scan gets ignored.
      - For a first LINE the remedy is `${text%%$'\n'*}` — pure bash, no pipe, no fork.
        `head -N <<< "$text"` is the herestring form where N is not one.
  - **An edit script asserts its anchor MATCHED, and a generator that produced
    nothing fails rather than reporting success.** The same family as the two above,
    reached from the authoring side rather than the checking side, and it happened
    three times in one night here:

    - a `sed`/Python edit that added compiler defines matched no anchor, changed
      nothing, and printed its success message anyway — found only because the same
      compile failed identically twice;
    - a PowerShell test fixture whose writer process silently wrote no lines, so the
      case it was written to exercise never ran and the test passed;
    - and a step-level `if:` inserted above an existing one, silently discarded by
      YAML's last-key-wins.

    Every one of them *reported success for work it did not do*, which is the thing
    this whole file is about. So: `assert t.count(old) == 1` before every
    replacement — **count, not presence**, because `>= 1` hides an ambiguous anchor
    that then edits the wrong occurrence, and `== 1` catches "missing" and "not
    unique" in one line. Print what was changed (how many, and which) rather than
    that the script finished; a run that reports `patched 0 of 3` is a run whose
    author notices, and `done` is not. The assertion earns itself the first time an
    anchor drifts under a rebase, which is not a rare event here.

    **And `count == 1` is necessary, not sufficient.** It proves the anchor was found
    and was unique. It says nothing about whether the insert was *correct*, because
    what an insertion breaks is usually not the text it replaced -- it is the text on
    the other side of it. **An anchored insert is checked against what FOLLOWS the
    anchor, not only against what precedes it.**

    Measured here, in this file, by the commit that added *A probe's result is only
    evidence if the probe could have produced the other one*: the anchor was the last
    bullet of a section, matched once, and the insert landed between that bullet and
    that section's *closing* paragraph -- a paragraph reading
    "Every finding in **both sections** is an instance of this" and listing five
    findings. Pushed below the inserted section, "both sections above" now pointed at
    that one instead, which contains none of the five. Nothing was misplaced and no rule
    was wrong; **a neighbouring paragraph was made false**, which is worse, because it
    now misinstructs a reader who never sees the edit.

    And a third correction inside this one entry, which is the point rather than an
    embarrassment: the first two accounts of this said the paragraph was stranded "four
    sections downstream". The commit that did it -- *a probe's result is only evidence
    if the probe could have produced the other one*, cited by subject because a rebase
    invalidated the hash this sentence first carried, which is the "name, not direction"
    rule one line of scope up -- inserted **one** section, and there were two by the
    time it was noticed. Nobody had counted; four was repeated from the first telling
    into a message and then into this file. **A number in a post-mortem is a
    measurement and decays like one** -- the incident is over, so nothing will ever fail
    to make it wrong again, and a rulebook is exactly where such a number goes to be
    believed forever.

    **And its mirror image, which that rule does not cover: a VERSION in a bug report
    is a measurement of the ENVIRONMENT, and the environment can change under it
    without anybody editing the report.** In the post-mortem case the claim decays
    while the world holds still; here the world moves and the claim is left describing
    a machine that no longer exists. #715 was filed against `g++ 16.1.1 20260515`; the
    host updated to `16.2.1 20260819` mid-session -- confirmed with `rpm -q gcc-c++`
    rather than inferred from the discrepancy, since "I misread it earlier" and "the
    package changed" look identical at a glance. The version was the only thing in that
    report saying WHICH compiler it was about, so it was load-bearing and had gone
    stale silently. Re-measured rather than assumed: it reproduces identically, same two
    files, same two `-Werror` categories, which is the answer that makes an update
    reportable rather than alarming -- and had it NOT reproduced, the report would have
    been describing a fixed bug while reading as an open one. **A reproduction is a
    claim about a machine as well as about a tree.** Name the version, and re-take it
    when the tool under it moves.

    **A prose diff cannot show you the sentence your insertion falsified.** The hunk
    was `@@ -898,6 +898,45 @@`: the added lines plus **six** untouched context lines,
    three leading and three trailing. Only the trailing three matter to the argument,
    and they held the first three lines of the paragraph that went false while the
    broken sentence sat four lines further down -- outside the window. So the diff was
    clean, minimal and reviewable, and the defect was invisible in it. (An earlier draft
    said "three", counting one side of a symmetric default. The paragraph below about
    post-mortem numbers was already written when that was found.) Re-read the whole enclosing section afterwards, from its heading
    to the next one, rather than the diff. In prose the specific hazard is a
    **back-reference**: "the section above", "both sections above", "the two entries
    below", "as stated earlier". Those are the sentences an insert silently redirects, so
    grep the neighbourhood for positional words before inserting between two things that
    refer to each other.

    That grep caught this very paragraph one minute after it was written: the sentence
    above said "the commit that added the two sections above", and those sections are
    **below** it. Which is the real remedy rather than the grep -- **point at a NAME, not
    at a direction.** A title survives an insertion, a rebase and a move; "above" is a
    claim about layout that every later edit can silently invalidate, and it is the only
    kind of claim in a rulebook that nothing in the tree can check.
  - **A tool given a path that does not exist reports nothing, which is what "absent"
    also looks like.** `nm` on a missing file prints no symbols, so a grep for one
    counts zero -- character-for-character identical to a binary that was built
    without instrumentation, and fixed somewhere else entirely. Test existence first
    and say which of the two it was; a single message covering both sends the reader
    to the wrong place.
  - **A second copy of a list is not a cross-check; it is a second thing to be
    wrong.** The scope check shipped in this branch first kept its own copy of the
    gate's Catch2 tags and its header claimed the two "are checked against each
    other". Nothing checked them: delete `[task]` from the gate's `TARGETS` row and
    `Async/Task_test.cpp` still matches the surviving copy, still reports covered,
    and six coroutine cases leave the sanitized scope with every signal green --
    the branch's own bug, one level up, asserted to be impossible. It parses the
    expression out of `scripts/tsan-gate.sh` now, and a `TARGETS` table it cannot
    parse is a hard failure rather than an empty scope. Duplicate-and-verify is a
    real pattern here (`check-service-accounts.cmake` reads three files to prove
    they agree), but the verify half has to actually be written.
  - **A known race lives in `.tsan-suppressions` with its issue number, never in a
    deleted check.** Every entry is an open bug; removing it is part of closing that
    bug. Write it `race_top:`, never `race:` — `race:` matches a function name
    anywhere in *either* stack, so it also silences a future, unrelated race that
    merely passes through that frame, and a teardown path like `Close()` is
    traversed by a great many stacks. `race_top:` matches only the frame the racy
    access is in. Either way an entry outlives the report it was written for, which
    is why the gate sets `print_suppressions=1` on **every** run, canary included,
    and prints ThreadSanitizer's own `Matched N suppressions` line.

## `NDEBUG` is not optimisation, and only the compiler can say which build this is

<!-- agent-tripwire: `NDEBUG` is not optimisation, and `CMAKE_BUILD_TYPE` is a LABEL that decides nothing -->

The same "the cache and the log are the two places that lie" rule, arriving where a
number gets quoted. `pace-bench` printed timings that said nothing about the build
behind them, and a Debug bench prints a plausible number: reviewing #1420 the manager read
an MSVC `cl-release` log as *"a Debug-build signature"*, and the only tell anywhere was the
build directory's **name** ([#1439](https://github.com/LASTRADA-Software/pace/issues/1439)).

Four things, and the first is the one that had already shipped as a defect.

- **`NDEBUG` does not say the optimiser ran.** `RaftPeerFrameBench.cpp` spelled its own
  `BuildKind` as `"optimised (NDEBUG)"`; `-O0 -DNDEBUG` defines it and optimises nothing.
  A figure labelled *optimised* on that evidence is a **confident wrong signal**, which
  this rulebook ranks below a vague right one everywhere else it appears.
- **`CMAKE_BUILD_TYPE` is a LABEL and decides nothing.** It rides into the binary as a
  compile definition and is printed, because an operator needs to know what was asked for
  — and no verdict reads it. Every verdict comes from a macro the **compiler** defines in
  the translation unit that asks, which is why `CurrentBuildConfiguration` is a non-inline
  function in one `.cpp` of the target rather than an inline one in a header some other
  target could instantiate with its own flags.
- **Which drivers state the optimiser is a claim about tools, so it was measured against
  the tools** (2026-09-15, on this machine, `-dM -E` over an empty TU):

  <!-- table-total: none -->
  | driver | `__OPTIMIZE__` at `-O1`/`/O1` and above | absent at `-O0`/`/Od` | `__MSVC_RUNTIME_CHECKS` under `/RTC1` |
  |---|---|---|---|
  | clang 22.1.2 (GNU driver) | yes | yes | n/a |
  | gcc 14.3.0 | yes | yes | n/a |
  | clang-cl 22.1.3 | yes | yes | **no** — it ignores `/RTC` |
  | `cl` (VS 18) | **never defines it** | — | yes |

  So an absent `__OPTIMIZE__` means *the optimiser did not run* on three of the four and
  means **nothing** on `cl`. `__SANITIZE_ADDRESS__` is defined by all four under their
  address-sanitizer flag, `__SANITIZE_THREAD__` by gcc and clang, and neither defines
  anything for UBSan — `__has_feature(undefined_behavior_sanitizer)` answers on clang and
  on gcc 14 and up, and MSVC has no `__has_feature` at all. clang-cl defines `__clang__`
  and **not** `__GNUC__`, which is why a predicate for *does this compiler state the
  optimiser* has to name both.
- **So a figure's standing has THREE values, not two.** A cost, not a cost, or
  **unconfirmed** — the last being a `cl` build with `NDEBUG` and no way to confirm the
  optimiser from inside the binary. Folding it into *a cost* is the wrong answer arriving
  as the plausible one, which is this file's recurring subject; folding it into *not a
  cost* would mark every MSVC release figure unquotable. `src/apps/pace-bench/BuildBanner.hpp`
  carries the fact table, and `ctest -R bench-build-banner` drives every arm over staged
  readings, because this host can only ever produce one of them.

The banner goes to **stderr**, and the reason is measured rather than assumed. Under
`--reporter xml` Catch2 redirects the streams a test case writes, so `std::cout`/`std::cerr`
from inside a case are captured into `<StdOut>`/`<StdErr>` and the document still parses —
but C stdio and `std::println` are not redirected, and a write from inside a `BENCHMARK`
body lands inside an open start tag and breaks the parse outright. stderr is safe for any
API, so the rule needs no exception for how a line was written. `ctest -R
bench-build-banner-streams` therefore asserts **no mixed content** rather than *stdout
parses*: a stray write between two elements leaves a document that parses perfectly and
carries text where only elements belong.

**And the rule is the whole binary's, not the banner's: stdout belongs to the reporter.**
Every line a bench file writes of its own goes to stderr -- the five files were moved onto
it with #1439 and `bench/inproc_bench.py` reads the `SCALING` lines off stderr because of
it. What makes that more than a sentence in the files that already obey it is that the same
check refuses a document whose `<StdOut>` carries any text at all, so a `std::cout` added
to a bench file tomorrow fails a check rather than being safe by luck about which reporter
is running and which endpoint happens to end in a newline.

## A retry makes every one of these disappear without fixing it

<!-- agent-tripwire: A retry makes an instrument's own failures disappear without fixing them -->

Eleven separate ways the gate reported something that was not about the tree under
test turned up across four tickets — a tally over THOSE FOUR, not a running total, and
it is written that way on purpose: `AGENT.md` carried a second, hand-kept figure for the
same fact and the two had drifted apart (twelve against eleven) before #1033 removed the
bare number there. This one at least DERIVES from the breakdown that follows, so a reader
can check it; a number nothing can derive from the thing it counts is a second source of
truth. Later instances are enumerated in `AGENT.md`'s list rather than re-counted here.
Six while fixing
[#493](https://github.com/LASTRADA-Software/pace/issues/493), two more while
fixing [#247](https://github.com/LASTRADA-Software/pace/issues/247), one while
fixing [#243](https://github.com/LASTRADA-Software/pace/issues/243), and two
while fixing [#292](https://github.com/LASTRADA-Software/pace/issues/292). Not
one of them announced itself. Every one presented as an ordinary flake, and **a re-run would
have cleared all of them without fixing any of them** — which is the whole reason they
are written down here rather than in those pull requests.

The specific traps are examples. The rule is the mechanism.

- **`local-gate.sh | tail`** reports the *pipeline's* last stage, so a run whose log
  ended in `GATE FAILED` came back as exit 0. Same shape as `producer | grep -q`
  under `pipefail`, above. Capture the status into a variable first; print the log
  after it.
- **Quoting through three parsers.** PowerShell → `wsl` → `bash -lc` silently dropped
  an escaped `$?`; the command collapsed, wrote no log, and exited 0. **A gate that
  did not run is not a gate that passed** — and an absent log is indistinguishable
  from a gate that produced nothing, unless you keep the log somewhere it survives.
  Author the commands in a script file and run the file.
- **Two gates in one build directory.** A run that had already *reported its verdict*
  was still driving `ninja` when the next one started. This is the worst of them,
  because the reading belongs to *neither* tree and neither process can detect it:
  from inside each one, everything looks entirely normal. `flock`, non-blocking —
  queued, the incident becomes invisible, which is the same defect as the failure it
  prevents.
- **A dirty or moving tree.** CI reads a commit; a local gate reads whatever is on
  disk as each phase touches it, so a long run can straddle an edit and different
  phases can judge different trees. An accurate verdict about something nobody asked
  about. Name the commit before starting, re-check it at the end, and refuse when the
  tree is dirty.
  - **An intermediate reading is BIASED, not noisy, and that is why the remedy cannot
    be "read it carefully".** A tree sampled mid-build can only be MISSING artefacts —
    never carrying extra ones — so its error is one-sided by construction: always
    toward failure, never toward success. Measured twice in one task: `ctest -L hygiene`
    at 235 of 429 build edges reported 2 failures where the settled tree reports
    **60/60**, and an earlier sample at 330 of 429 reported 1.
    The consequence is the part that changes behaviour. A mid-build failure is exactly
    what a real regression looks like, so the natural response — investigate it — is
    the wasted motion, and no amount of care in INTERPRETING the reading recovers
    anything, because the reading contains no information about the finished tree. So
    the discipline is **do not take the reading**: wait for the build's completion
    signal rather than sampling a tree that is still being written. Both hits above
    were caught only by re-measuring afterwards, and in both the alarming number came
    first.
- **The log under `/tmp`.** `wsl -e bash` detaches, so a build outlives the wrapper
  that reports on it — and the wrapper is what keeps the WSL session alive, so
  *killing it to tidy up* starts an idle countdown that takes the VM, the orphaned
  build and `/tmp` with it. Write the log to `/mnt/c`.
- **The instrument edited while it was measuring.** bash reads a script incrementally,
  from a byte offset, so editing the wrapper the gate was running re-ran its header
  block and shifted an `exec 9>` redirect into a different path — and the run
  continued **with no lock while reporting as though it held one**. A guard that
  silently stopped guarding.
  - **It reports in whichever direction the read pointer happens to land**, and the
    second direction is the one that gets believed. Editing a gate wrapper *to improve
    it* -- adding the commit stamp the entry below asks for -- while that wrapper was
    mid-run shifted every offset after the insertion, and bash resumed inside a later
    line: `syntax error near unexpected token '('` on a `(` that had been inside
    double quotes since the file was written. The gate itself had already **passed**
    both legs; the corruption landed in the *reporting* step, so the task reported
    `exit 2` for a green tree and never copied the log out. A false PASS hides a
    defect, a false FAIL invents one, and a false FAIL that a re-run clears is how a
    working gate gets a reputation for flakiness.
  - So: **launch long-running scripts from an immutable per-run copy**, and do not
    edit an instrument that is currently running -- *including to improve it*, which
    is the version that feels safe and is not.
- **A path mangled between shells, and the wrapper exiting `0` having run nothing.**
  `nohup wsl.exe -e bash /mnt/c/...` launched from Git Bash becomes
  `C:/Program Files/Git/mnt/c/...`: Git Bash rewrites a leading `/mnt` as though it
  were a POSIX path inside its own install prefix. `bash` then reports
  `No such file or directory` — on stderr, from the launched process, which the
  backgrounding discarded — and the launcher returns **success**. This is the purest
  specimen in the set: not a wrong answer, an *absent* one wearing a right answer's
  exit code. Run `wsl` from PowerShell, where the path survives, and check that the
  log the run was supposed to write exists before reading anything into its contents.
- **The wrapper dying on its own log while leaving the work alive.** The gate log
  lived on `/mnt/c`; DrvFs refused the redirect once — `No such file or directory` on
  a directory that existed and was writable seconds later — so the wrapper exited 1
  having run nothing **and left the gate child running**. That is worse than a clean
  failure: an orphaned run means the next reading is ambiguous between "nothing
  happened" and "something is still happening", and the tree it is building is no
  longer the one anybody is looking at. **An instrument must not depend on the
  filesystem it exists to measure** — write the log to ext4 and copy it to `/mnt/c`
  at the end, which keeps it surviving a WSL idle-out without putting DrvFs in the
  path of opening it.

- **The instrument edited the tree and then measured what it had edited.** Not a
  mix-up: no wrong path, no stale ref, no forgotten `cd`. `scripts/local-gate.sh` runs
  `clang-format -i` as its first leg, so a commit that was not already formatted is
  **rewritten**, and the build and test legs then judge the rewritten tree. The gate
  measured exactly the tree in front of it, and the tree in front of it was no longer
  the commit *because the gate had changed it*. An observer effect rather than a
  confusion — and every `--fix`-mode tool has the same shape.
  - **The guard failure is structural, not an omission.** A dirty-tree check that
    samples **once, at the start** cannot detect a change caused by the thing it is
    guarding: the tree was clean when it looked. That is why "check the tree is clean
    before you start" is insufficient on its own, and why the entry above says *name
    the commit before starting, re-check it at the end*. Sampling at both ends is the
    only shape that works.
  - **Implementing half of a two-clause rule looks exactly like compliance.** The
    wrapper that met this printed `N_GATE_COMMIT` and `N_GATE_DIRTY` before the run and
    never again — the first clause faithfully, the second not at all. Nothing in the
    output says a clause is missing, which makes this the most common way a two-part
    rule fails.
  - **"It's only formatting" is a claim, not a fact.** The delta was line wrapping and
    one include reorder, which is where almost anyone stops. An include reorder changes
    a translation unit's contents and can change what compiles. Amend the formatting
    into the commit and **re-run** the legs that measured the other tree, rather than
    reasoning about whether whitespace could matter.

- **A `ctest` total is only a total for the target set it was configured with.**
  `-DPACE_BUILD_TESTCLIENT` and `-DPACE_BUILD_BENCHMARKS` default OFF, so
  two runs of *one commit on one platform* report different totals, and **nothing in
  the output says which you asked for**. A gated-off target is invisible to the run
  rather than absent from it: the suite passes, the count looks like a count, and the
  tree simply appears smaller. This is the rule about a clang-tidy sweep being only as
  complete as its compile database's targets, arriving at a different instrument and a
  different artefact.
  - **So a total needs three conditions before it is comparable**, not two: the same
    tree, the same platform, **and the same target set**. Two were already written
    down; the third is the one that reads as a smaller codebase rather than as an
    error.
  - **Caught by arithmetic, and only because the number could not be lower.** A branch
    adding five cases reported 2982 where a sibling branch adding one reported 2992 on
    the same base — impossible in that direction. Reconciled, both fall out of one
    base once the conditions match: 2996 = 2991 + 5 against 2992 = 2991 + 1. A
    plausibly-*higher* wrong number would have passed unexamined, which is the honest
    boundary of this check rather than a reason not to make it.

- **An artefact that does not identify its subject cannot be told from a current
  one.** A WSL idle-out emptied `/tmp` mid-cycle, and the durable copy of the
  PREVIOUS run's log was left sitting exactly where a reader looks for the current
  one — reporting a failure that had already been fixed, in a file that had every
  appearance of being this run's. What distinguished them was a file timestamp that
  happened to predate the commit under test: an **accident**, not a property. Two
  runs landing in the same minute, or a clock that is off by a few, and there is
  nothing left to read at all.
  - **A verdict must carry what it is a verdict about.** The commit and the branch go
    *inside* the log, written before the gate is invoked — not only onto the
    wrapper's stdout, which is what dies with the terminal — for the same reason the
    gate prints its gitdir in its own header.
  - This is a **different mechanism** from the `/tmp` wipe it was discovered through,
    and the worse of the two. The wipe destroys the current answer, which is loud;
    this one leaves a stale answer looking current, which is read and acted on.

Two that are not about shells at all, and are the ones a reader is most likely to
recognise in themselves:

- **A finding fixed at the line rather than at the rule comes back.** clang-tidy
  reported `bugprone-unchecked-optional-access` at two lines; the rule is "clang-tidy
  cannot see that Catch2's `SKIP` does not return, so a bare dereference after one is
  always this error". Fixing the two lines left the identical defect in the half of
  the tree the report had not happened to name, and a refactor then moved the line
  numbers so it did not resurface for two more gate cycles. Read a finding as a
  statement about the tree, not as a list of locations.
- **Presence is not usability.** A probe asks whether the tool *did the job*, never
  whether it exists. A `clang-cl` with no MSVC SDK is on `PATH`, spawns perfectly and
  can build nothing; so does a driver whose toolset was uninstalled under it. The
  only question that survives is "did an object appear?" — which is the same lesson
  `dist-compile-e2e.ps1` records for `Get-Command`, and the same one behind
  `exitCode == NotSpawned` being a guard about *running*, not about *working*.

The asymmetry is what justifies the cost. **Looking costs minutes; retrying turns a
wrong reading into a permanent one**, because the evidence that something was off is
gone and the next run starts clean. Every one above was caught only
because something looked slightly wrong and got *looked at* rather than re-run — a
log sitting at zero bytes for slightly too long, an output file containing a single
backslash, an exit code disagreeing with its own log's last line, a finding
reappearing that had supposedly been closed.


### Five more, all from `wsl.exe`, and none settled by an exit status or a log

These arrived in one evening from four lanes, and the property that ties them is that
**NEITHER the wrapper's exit status NOR the presence of a log settles whether the gate
ran**: two produce exit 0 with no work done, one produces no artefact at all, one
produces a status about the wrong process, and the fifth produces a log whose body is
perfect and whose opening lines have been overwritten.

- **A BACKGROUND LAUNCH that started nothing and said so in the affirmative.**
  `A && B && nohup C & echo STARTED` binds the `&` to the WHOLE `&&` list, so the marker
  is printed by the launcher before anything it describes could have failed. Under
  `wsl.exe` the detached job then dies with the invocation that started it whether or not
  `setsid` and `nohup` are spelled. The tell was that the log file did not EXIST — never
  the exit status.
- **Its sharpest form: `nohup` inside `wsl.exe -e bash -lc`**, where the child dies with
  the WSL session and the log is never CREATED. Not stale, not truncated, **absent** — so
  there is no artefact to examine or date, and absence is exactly what a lane reads as
  *still running*.
- **`GATE_EXIT=$?` inside a `wsl.exe` string is the OUTER shell's**, reporting `0` over a
  run that had just printed `TSAN GATE FAILED`.
- **`setsid` FORKS when the caller is already a process-group leader**, so the parent
  returned instantly and `GATE EXIT=$?` recorded **0 before the gate ran a step**, which a
  waiter keyed on that string then believed. It was caught because the line sat ABOVE the
  gate's own `LOCAL GATE STARTED` marker: an **ORDERING** check, where every value check
  agreed with it.
- **A wrapper's `>` redirect OVERWRITES the gate's own markers, and the log that results
  reads perfectly.** `wsl.exe -e bash wrapper.sh > gate.log` opens with `O_TRUNC` and
  **without `O_APPEND`**, and the gate's `flock … env … /usr/bin/bash local-gate.sh`
  re-exec reopens the same path — so later output is written from offset zero and eats
  the opening lines. Observed: a 38-line log with **no `GATE LOCK WAITING` and no
  `LOCAL GATE STARTED`**, and line 4 beginning mid-word (`mnt/d/...`, missing
  `worktree: /`). Everything after was intact, which is the whole problem: the body is
  the part a reader skims and it looked complete, so a green run would have been quoted
  with no idea which commit it was about. **The truncated first line reads as a torn
  cross-filesystem read** — the log was written by WSL and read from Git Bash, where that
  is the likelier cause — and it was ruled out only by re-reading from the WRITER's own
  filesystem, where the absence is identical. Remedy: `>>` onto a pre-truncated file, or
  let the gate write its own log.

So the wrapper writes an artefact **BEFORE** the gate starts, naming the commit it is
about, which makes *the wrapper ran* checkable independently of *the gate produced output*
— and the verdict itself is read from the tool's own terminal text, never from a status.

**That rule has now been seen to pay, which is worth recording because a guard nobody has
watched work is the one that gets dropped as belt-and-braces.** In the overwrite above the
in-log `LOCAL GATE STARTED` marker was destroyed, so the run's subject was unrecoverable
from the log itself; the wrapper's own pre-artefact still named `commit 6eed271d,
2026-09-20T07:05:25Z`, and that is the only reason the run could be attributed at all.

**`pgrep -f local-gate.sh` cannot settle which gate is whose.** It found three gates, none
of them the asking lane's, and every one matched the same pattern; `readlink
/proc/<pid>/cwd` per pid is what named them.

### A killed run has told you nothing, which is not the same as telling you the tree is fine

Two full gates ran concurrently on one host, swap went to 7G of 7G with no OOM kill logged,
and one died mid-build with exit **144**. **A nonzero exit from a KILLED gate is not a red
tree** — 144 turned up twice that day in unrelated contexts, so it means *something killed
this* and never *the tree is bad*. Discard the run rather than reading it.

### Serialise the gate across lanes with a LOCK, and a poll-for-zero is not one

*"Wait until no other `local-gate.sh` is running, then start"* reads as mutual exclusion and
behaves like it **only while there is a single waiter**, which is the condition it is
invariably tested under. With N waiters it fails twice:

- **It STARVES.** It waits for zero rather than for the set running when you arrived, so
  every later arrival extends your wait. Measured on this box: a lane queued at 5:35 was
  still waiting at 15:57 while one that arrived ten minutes later started and finished first.
- **It is a THUNDERING HERD.** When the running set drains, every waiter's next poll sees
  zero and they all start at once — which is the concurrent-gate storm the rule exists to
  prevent, arriving at the moment adoption is complete and looking exactly like nobody
  following the rule.

`flock` on a lock file, never `fcntl`, for the reason the storage and scratch-root rules
already give: an `fcntl` lock is per PROCESS, so two gates inside one shell would both take
it and succeed. It is not FIFO, so a lane can be unlucky; unlucky-and-bounded is not
starving and cannot stampede, and it **must not be "improved" into a queue**.

### And the gate takes the lock ITSELF, on ONE path it defines (#1379)

Everything above was right, and satisfiable in a way that did nothing. `local-gate.sh` took
no lock: serialisation lived in each session's wrapper, nothing in the repository named a
path, and every lane invented one, so two lanes serialised only when their spellings happened
to coincide. Measured: one lane's `flock` sat on a path no other lane used, three gates ran at
once on one host, and that lane's lock acquired instantly every time. **A lock nobody else
takes always acquires, which is indistinguishable from a free host — the lock's success WAS
the symptom.** The queueing that lane did observe came from a separate hand-rolled wait loop,
so the broken mechanism sat behind a working one where nothing could see it.

So the lock is taken by the thing being serialised, and omission stops being possible:

- **One path, defined once in the script** — `$HOME/.pace-local-gate.lock`, overridable
  by `PACE_GATE_LOCK`. **Per user, and chosen rather than settled for.** A host-wide path
  means `/tmp`, which WSL wipes when it idles out, and `flock` on a file unlinked while held
  leaves the holder locking an orphaned inode while the next opener creates a fresh file and
  acquires it: two holders, no error from either. That fails silently in exactly the direction
  the lock exists to close, where the per-user limit is stated — in the lock's own output lines.
  It does not cover CI, another machine, another user, or Git Bash against WSL on one Windows
  box, whose `$HOME`s differ.
- **After `--classify` and `--self-test`, and before the start marker.** `--self-test` is the
  ctest entry `local-gate-selftest`, which the gate itself runs, so a lock taken before that
  exit makes the gate queue behind itself for the whole wait. Before the marker, because the
  marker names the commit, and a lane committing while its gate queues would otherwise get a
  verdict naming a commit nobody measured.
- **`flock -o`, never a descriptor the run keeps.** A descriptor is inherited by every
  descendant, so a daemon an e2e fixture leaked would hold the gate lock for the life of the
  machine and every later gate would queue for the whole budget and refuse. `-o` releases the
  lock when the run ends. The price, MEASURED because the first version of this sentence got
  it backwards: killing the waiting parent alone leaves `flock` and the run going with the
  lock still held, while killing the **`flock` process** alone frees the lock under a run that
  carries on, so a second gate starts beside it. Kill the process GROUP.
- **A wrapper that already holds the lock is DETECTED rather than deadlocked against** — which
  is what keeps every existing `flock <path> bash scripts/local-gate.sh` working, since a second
  descriptor on the path would block against the wrapper's own. Two detectors, because neither
  covers both cases: a marker the gate exports for its own re-exec, believed only when its pid
  is an ANCESTOR, and a scan of the ancestors — never only the parent — for a `flock` naming the
  same file. The marker is asked first, because the gate's own re-exec sits directly under a
  `flock` naming that very lock and a single pass would call it a redundant wrapper. A wrapper
  holding a **different** path is its own outcome, printed with both paths, and the gate takes
  its own lock too: folded into *held* or *free*, a mistyped wrapper would be serialised against
  nothing and told nothing. A wrapper holding THIS lock `-s` or `-u` excludes nobody and is
  refused at once. The argv is read the way util-linux reads it — abbreviated long options,
  `=` values, digits that are a FILE when a command follows — because a parser that disagrees
  with flock's answers wrongly in both directions, silently one way and as a deadlock the other.
  **What detection cannot see**: a lock held through a descriptor an ancestor opened, or by
  `flock -F`, which becomes the gate rather than its parent. Neither leaves a `flock` above the
  gate, so the gate waits on it and its refusal says so. And an ancestry that cannot be READ to
  its root — no `/proc`, no `ps` — is reported as unknown, never as free: the parent pid comes
  from `/proc/<pid>/stat` first precisely so that a host with util-linux and no procps does not
  queue behind its own re-exec.
- **`GATE NOT STARTED:` is an outcome, never a verdict** — `lock-not-acquired` when another gate
  held the lock for the whole wait, `lock-unusable` when it could not be taken at all, each with
  a status of its own and each read back by `--classify`. A queued run prints
  `== GATE LOCK WAITING` first, so contention is observed rather than inferred from a long wall
  time. The self-test proves it by CONTENTION — refused while held, acquired once released —
  because a lock that acquires proves nothing, which is this whole section. **And it drives the
  REAL path, not stand-ins**: the script itself, stopped by `PACE_GATE_STOP_AFTER_LOCK`
  once the lock stage has decided. Its first version exercised `gate_lock_run` with `sh -c`
  commands only, and a review showed three one-line mutants of the real path — the marker
  exported under another name, the sentinel never touched, the ancestor walk returning nothing
  — each passing it 208/208 while breaking every real run.
- **A host without `flock` is told so and runs UNSERIALISED**, loudly. Refusing there would be a
  gate that fails closed unconditionally on that host, which reads as *my branch is bad*.

## A count that OVERSTATES what is wrong is the same defect as one that understates it

<!-- agent-tripwire: A count that OVERSTATES what is wrong is the same defect as one that understates it -->

Everything above is about an instrument reporting **fewer** things than are wrong, or
reporting on the wrong subject entirely. The other direction is a defect of exactly the
same kind and had no entry here until #796:

> **A verdict must be a verdict about something, and an instrument that cannot say how
> many things are wrong cannot be trusted about WHICH.**

**The tell is an arm reporting a number nobody can explain**, and that is the only
actionable half. All three instances below were caught that way. None was caught by
reading the code, and one had already been read twice.

**The two directions are not symmetric in practice.** An under-report is silent and gets
found late. An over-report is **loud and misattributed**: it sends somebody to a defect
that is not there, and when they find nothing it discredits the instrument — so the next
real finding from it is discounted too. In instance 1 the phantom second line was a
sentence fragment that a reader would reasonably have chased.

Three instances, all in one change (#680, PR #795), and they are three distinct
mechanisms rather than one bug told three ways:

- **A literal `;` split one finding into two** (#796, instance 1). CMake treats a
  semicolon inside a list element as an element boundary, so
  `list(APPEND violations "... in cmake/Packaging.cmake; either the hook is gone or ...")`
  became two elements and `list(LENGTH)` counted **2** for one defect. This is the exact
  hazard `check-script-check-signals.cmake`'s own header documents at length for
  `file(STRINGS)` — *"a line containing a semicolon becomes two elements"* — met one
  function over, **in the file that documents it**. A rule stated in the file that obeys
  it is not learned by the file that does not.
- **An edit that inserted a statement inside another statement's argument list.** A
  `string(REPLACE ...)` landed between `list(APPEND violations` and its message argument,
  so CMake parsed `string`, `(`, `REPLACE` as arguments to `list(APPEND)` and the run
  reported **`10 finding(s)`** with an empty path. The edit script asserted its anchor
  existed and was unique — which this file already requires — and **a match is necessary
  and not sufficient**: the insertion POSITION must also be structurally valid.
- **A missing file reporting three findings for one cause.** With `cmake/Packaging.cmake`
  absent, the pass appended one violation for the missing file and then **the loop still
  ran**, so each of two hook variables added another. Three findings, one cause. Found by
  applying the first instance's lesson deliberately rather than by it biting, which is the
  direction this clause exists to produce.

**And the CMake argument-passing fact that cost a cycle finding these.** A `macro()`
substitutes its arguments **textually** and CMake then re-parses them, so a backslash
escape inside a pattern is consumed **twice**: `"\\("` written at the call site arrives
at `MATCHES` as a bare `(`, a regex group opener, and fails to compile. A `function()`
does not, because the argument is a variable. The failure is at **regex-compile** time,
which reads as *my pattern is wrong* rather than as *my macro ate a backslash*.

The remedy in `check-script-check-signals-selftest.cmake` is that patterns passed to a
macro carry **no backslash escapes at all** — a literal `(`, `.` or backtick is written as
`.`, which is laxer than an escape and is the price of a pattern meaning the same thing at
the call site and inside the macro. Quadrupling the escape is correct, unreadable, and
will not be maintained.

That is one half of a larger fact about macros, and the other half is
[#1216](https://github.com/LASTRADA-Software/pace/issues/1216): because the
parameters are TEXT rather than variables, `if(param STREQUAL "x")` inside a macro
compares the literal string `param` and the branch is **silently dead**. Same cause, two
symptoms, and neither has a diagnostic — one fails loudly at the wrong layer, the other
does not fail at all.

## A claim about a tool is checked against the tool

<!-- agent-tripwire: A claim about a tool is checked against the tool -->

The section above is about instruments reporting on the wrong tree. This one is about
the step before: **reasoning about what a tool does instead of reading what it does.**
Both were found in the same hour as the last two entries above, and they are the same
error one level up — a general claim standing in for a specific one.

- **A pattern is broader than its author reads it as.** `pgrep -f "scripts/local.gate"`
  was written to name one file and is a **regex**: the unescaped `.` matches the `-`
  in `local-gate.sh`, so it matched a family. Distinct from a pattern that is
  deliberately broad — this one *looks* exact. It also matched its own invoking
  shell, which is why it returned 143 and why the count it reported included itself.
  `pgrep -F` for a fixed string, or anchor it. And a cleanup that is about to send a
  signal identifies its targets by the **process tree**, walking to an ancestor that
  owns a directory this session owns — never by a command-line match, and not by the
  leaf's `cwd` either: a wrapper's `cwd` is where it was launched, and CMake's is a
  `TryCompile` scratch directory. Judging a process by an attribute inherited from its
  launcher is the adjacency-attribution rule with a third way to be adjacent.
- **A guard that has never been seen to refuse is not a guard.** A dependency clone
  wedged for 43 minutes in `read()` on a socket that had delivered zero bytes, because
  `http.lowSpeedLimit`/`http.lowSpeedTime` are unset and git therefore applies no
  timeout to a transfer that stops delivering. Setting them turns a permanent hang
  into a named failure after 60 seconds of silence — and the next run **succeeded**,
  which proves nothing about the bound: a cold `CPM_SOURCE_CACHE` still fetches once,
  so that populate crossed the network too and merely did not stall. The bound is
  **untested, not proven.** Reporting it as vindicated because the run it accompanied
  passed is the same defect as every entry above, and the same one
  `tsan-canary-rate.sh` exists to prevent.

- **The tree you measured is not necessarily the tree in question.** A grep for a
  constant found it at `main.cpp:135` with two uses, contradicting a report that it
  had been deleted — except the primary checkout was parked on a branch merged days
  earlier. Against `origin/master` the constant is gone. This is the worst-behaved
  member of the family: the others produce a missing log or an absent answer, and this
  one produces a **confident correction**, which propagates — it is about to be sent to
  somebody who will act on it. The tell is not in the output, because the output looks
  exactly like a finding. It is that **the answer was too convenient**: it made a
  teammate wrong and the reader right, with no effort. Check what you grepped —
  `git rev-parse HEAD` in the directory you searched — before reporting a contradiction
  as a fact. It happened twice in one night, both times in the same direction.

**The general form, and it is the one worth carrying away.** "A SIGTERM does not take
55 seconds to arrive" was offered as evidence in an incident review. It is true of
`local-gate.sh` — and *only* because that script traps `EXIT` and not `TERM`. bash
defers a **trapped** signal until the running foreground command returns, so a signal
trap on the same line would have made a TERM at second four produce a death at second
sixty-nine, and `143` is what bash reports either way. The general claim and the
specific one point opposite directions, and nothing about the general one advertises
that it does not apply. **Check the claim against the tool in front of you, not
against how tools of that kind behave.** Every finding in both sections is an instance
of this: a pipeline's exit code, a `.` in a pattern, a `cwd`, an unset git timeout, a
signal disposition — each one a fact somebody knew generally and did not verify
locally.

## A probe's result is only evidence if the probe could have produced the other one

<!-- agent-tripwire: Run both directions: which one you skipped decides which way it lies -->

The two sections above are about an instrument reporting on the wrong tree, and about
reasoning where reading was called for. This is the third: **a measurement that was
honestly taken, of the wrong thing, and read as an answer about the right one.** Both
halves below came out of one investigation (#726) in a single session, they point in
opposite directions, and neither was a wrong answer — each was a **non-answer wearing
an answer's colour**. One was a red that meant nothing; the other a green that meant
nothing.

- **A green probe of the wrong shape is not a refutation.** A review reported that
  under `Fsync` the commit after a one-slot meta recovery overwrites the surviving
  slot. Two probes were built and both came back clean, and "the finding is wrong" was
  written down before the third existed. Both seeded the store through raw `CowTree`,
  one flush per commit — which *keeps* the `txnId` slot parity, and the broken parity
  is the whole precondition. Only the `CowTreeStorage`-shaped seed reproduces it, where
  the FIRST `Open` commits the format marker -- `EnsureFormatVersion` stamps it on a
  brand-new store only, so the two sessions total 6 commits then 5 and the parity ends
  up broken. Written as "`Open` itself commits the marker" at first, which would make
  the total even and the fault unreachable. The finding
  was true. **Before recording a negative, state what would have had to be true for
  the positive to appear, and check the probe had it** — a fixture that cannot exhibit
  the fault cannot vote on it. Same defect as a suite exercising the fallback path
  while CI exercises the git path, and as a `want-fail` case satisfied by the shell
  refusing to start.
- **A single observation is a snapshot, not a trend, and cannot tell a transient from
  a fixed point.** The probe that finally did reproduce it committed **once**, so
  "after" meant "after one commit" — and that was published as "every subsequent
  commit hammers the same slot, so the store stays permanently one torn write from
  unopenable". Measured over five consecutive commits: `valid: 1` after the first,
  `valid: 2` from the second on, because the offending write restores the parity and
  the next commit repairs the damaged slot. A real defect, overstated into a different
  false claim, which then shipped in an operator page. **Iterate the operation, do not
  merely perform it.** The tell was available and unread: the same filing already noted
  the parity being restored, two sentences from the claim that contradicts it.

The pair is worth more than either alone, because the mistake is symmetric and the
instinct is not: a green probe invites you to close the question, and a red one invites
you to describe it — and the second is where a bounded fault becomes an unbounded
sentence. The storage-side instance is in
[`storage.md`](storage.md); the general form is here.

## A correction is a search, not a recollection

<!-- agent-tripwire: untriaged: #1567 no AGENT.md bullet carries this rule; the nearest is testing.md's census rule, which this section itself calls borrowed -->

The section above is about acquiring evidence. This one is about **repairing a claim
after you have it**, which fails its own way: a wrong statement is rarely written down
once, and the copies you can list are not the copies that exist.

**A claim corrected in the places you remember writing it is not corrected.** One false
sentence about the `fsync` exposure above went into an issue body, a pull request that
another session then merged, and a rulebook paragraph. Two were fixed from memory; the
third survived, and survived a rebase, because it was never re-read — `grep -n "hammer"`
found it in four seconds after recollection had already failed twice. So the fix is a
search over the tree and the tracker, not a list of the places you think you touched.

**And a search is only as good as its pattern.** The follow-up search for surviving
copies came back clean, correctly — but the same session's check for the **corrected**
text also came back empty, which was impossible, since it had merged that text itself.
The content was there and the pattern could not reach it: the prose is line-wrapped and
carries markdown emphasis *inside* the phrase, so no phrase-grep matches it.

```
So on `fsync` the dangerous moment is the **first write after a degraded
start**, not the indefinite future.
```

That is the census rule from [`testing.md`](testing.md) — a zero that was expected, and
therefore never questioned — arriving in prose rather than in a test count. **Give a
search that returns nothing a positive control**: find one instance by other means and
check the pattern sees it. On wrapped markdown, match a single distinctive word, or
strip the wrapping first; never a phrase that spans a newline or a `**`.

### A reason that generalises further than the fact it was drawn from is worse than the narrow one

The section above is about a claim that was WRONG and did not get corrected everywhere.
This is the sibling that is harder to see: **a claim that was RIGHT, and was then improved
into a wider one that is false.**

A reason recorded beside a decision is read as licence. A narrow reason licenses exactly
the site it was measured at; a wider one licenses every site somebody can fit under it,
including the ones nobody measured. So **a reason that generalises further than the fact it
was drawn from is worse than the narrow one**, even when it is more elegant, and even when
it happens to be true where it was written — because what it authorises is an edit
somewhere else.

**And it is introduced while TIDYING, which is when it is least likely to be re-checked.**
Nobody re-derives a reason during a cleanup: the behaviour is unchanged, the tests stay
green, and the diff reads as prose. Measured on `Net::IsDeadlineExpiry`, where a true
REACHABILITY reason — *that listener arms no poll timeout, so `Timeout` cannot arrive
there* — was rewritten during a `/simplify` into a semantic one that sounds better and is
false, a later review faithfully propagated the replacement into two rulebook files, and
the header then argued both sides. The full derivation, including what believing the wider
reason invites somebody to delete, is in
[`wire-and-protocol.md`](wire-and-protocol.md).

Two consequences:

- **A narrower rule with a stated reason is not the same finding as a narrower rule by
  omission**, and the grep looks identical. Reading the first as the second is how a
  correct site gets "fixed".
- **A reason states what it does NOT cover**, at the site, or the next reader over-applies
  it — the same clause the remedy-text rule carries for a guard's refusal message.

## A comment can be true in its premise and false in its conclusion

<!-- agent-tripwire: a full replacement computed from the labels it read when its run started -->

`pr-labels.yml` carried this, and every word before the comma was correct:

> `sync-labels: true` ... only ever touches labels named in the config, so
> `type/`, `priority/` and `status/` are out of its reach by construction.

`.github/labeler.yml` genuinely contains no `type/` row, and the action's deletion
logic genuinely is config-scoped. The conclusion was still false, and it cost three
red `Require a type label` gates in one evening — presenting as three different
problems, which is why it survived being seen repeatedly.

- **The deletion is config-scoped; the WRITE is not.** `actions/labeler` seeds its
  set from the labels it read when the run started, then finishes with
  `setLabels(...)`, a full replacement of the pull request's labels —
  **unconditionally, whether or not `sync-labels` is set**. So any label added
  between that read and that write is destroyed regardless of prefix or config.
  **Turning `sync-labels` off would not have fixed it**, which is worth stating
  because that was the obvious fix and it was aimed at the wrong mechanism.
- **It is a lost update, so it is intermittent, so it reads as flakiness.** The
  action only writes `if (!isEqual(labelsToAdd, preexisting))`, so the window bites
  only on runs that actually had a label to add. Labelled while such a run is in
  flight: lost. Labelled when nothing is in flight: kept. Three pull requests in one
  evening showed label-stripped, label-kept, and a `CANCELLED` gate — one defect,
  three presentations, none of which looked like a labeller bug.
- **Read the timeline before theorising.** `gh api .../issues/<n>/timeline` names the
  actor and the second for every label event, and it settled in one query what two
  rounds of plausible hypotheses had not. Both of the hypotheses on offer — "the
  gate evaluated before the label landed" and "v5 removes unmatched labels" — were
  wrong, and each was confident enough to have been acted on.
- **Verify a third-party action against its source, not its README.** The behaviour
  that matters here is one `setLabels` call that neither the input's name nor its
  documentation suggests.
- **The repair is a compensating action and says so.** Nothing in a workflow can
  stop the replacement, so `pr-labels.yml` brackets the action: remember every
  label the config cannot produce, and restore what the write destroyed. It emits a
  `::warning::` when it fires, because a silent repair would leave nobody knowing
  how often the race occurs — which is exactly how the original survived.

## A `cmake -P` check cannot fail its own test

<!-- agent-tripwire: A `cmake -P` check is judged by its OUTPUT, never by its exit code -->

This section used to open by stating, as a measurement, that `message(FATAL_ERROR)`
in script mode prints `CMake Error ...` and then exits **0** on CMake 3.28 — this
project's declared minimum — so that every `cmake -P` hygiene check reported
PASSED however loudly it had just objected. **Thirteen registrations, and this
rule, rest on that sentence, and it does not reproduce** (#565).

- **What reproduces.** Exit **1**, on 3.22.6, 3.25.2, 3.27.9, 3.28.3, 3.31.6 and
  4.3.0, for six script shapes — bare, inside `if()`, inside `function()`, inside
  `foreach()`, inside `macro()`, and `SEND_ERROR` — each reading taken with
  controls proving the harness could report a zero. Two machines in the ticket
  read the same on Ubuntu's 3.28.3 and on Windows. The claim is now **asked**
  rather than remembered: `ctest -R fatal-error-exit`, in the default set, so
  every platform CI builds answers it on every run. A red one is a discovery —
  the condition has been found somewhere — not a defect in the check.
- **How a measured claim came out wrong, which is the transferable part.** A TRUE
  neighbouring fact carried one clause too far. A `-P` script genuinely cannot
  **choose** its exit code before CMake 3.29 — `cmake_language(EXIT)` is 3.29, and
  on 3.28.3 it is an unknown command, measured — which is why the SKIP direction
  correctly uses `SKIP_REGULAR_EXPRESSION` rather than `SKIP_RETURN_CODE 77`.
  *Cannot choose its exit code* then became *cannot signal failure by exit code*,
  and `message(FATAL_ERROR)` hands you exactly one code you did not choose, `1`,
  which is the only one a failure needs. Both reproducible ways to see a 0 are
  instrument shapes rather than CMake versions: an unguarded pipeline (`cmake -P …
  | tail` reports the pipe's status) and a nested `cmake -P` whose
  `RESULT_VARIABLE` is unread. The first is this file's own eleven-ways bullet;
  the second is now what `script-check-canary` is built out of.
- **A census over CORRECTED prose must CLASSIFY, and a census that only counts is
  wrong in the direction that looks like unfinished work.** Retiring the claim
  above left thirteen places quoting it in order to refute it, because this file's
  house style is to leave the wrong sentence visible — that is what lets a reader
  tell *corrected* from *never said*, and a silent swap would have made the
  retirement unauditable from outside. The cost is that **the pattern which finds
  the claim finds its refutation too.** Three readers grepped for it after the
  correction landed and each reported a live copy; all three had read a
  retraction, and the worst-looking hit —
  `src/tests/CMakeLists.txt:143`, which carries *"measured, not inferred"*, the
  phrase this repository uses to mark a claim as trustworthy — has that phrase
  **inside the quotation marks**, three lines above its own refutation.

  The method, because a figure without its pattern is the defect this section is
  already about. State the query, then classify each hit rather than totalling it:

  ```
  git grep -nE 'exits? \*?\*?0\*?\*? on (CMake )?3\.28|cannot fail by exit code|exits 0 on 3\.28'
  ```

  then, per hit, read ±6 lines for a retraction marker (*does not reproduce*,
  *paragraph said*, *stated ground*, *until #565*) and report ASSERTION or
  RETRACTION. Asked at `7952c61f`: **13 hits, 13 retractions, 0 assertions** — the
  claim held, which is an outcome worth recording precisely because it is the one
  nobody writes down. **14 on the tree that carries this bullet**, the extra being
  the query above matching itself: state which tree, as always, and note that a
  documented census counts its own documentation.

  **Zero is not a verdict, so the classifier gets a positive control.** A broken
  classifier and a clean tree produce the same output. Plant one bare assertion
  far from any marker — `scripts/check-test-names.cmake:4` was used — confirm the
  census reports `ASSERTION`, then restore. Without that step "0 assertions" is an
  absence of evidence rendered as evidence of absence, which is this rulebook's
  own four-states rule arriving in an audit.

  **And the classifier is a triage aid, not an oracle — measured, it is blind
  around this very paragraph.** The marker list two paragraphs up is prose in the
  same file, so it puts a false-RETRACTION zone ±6 lines around itself: a bare
  assertion planted three lines from that list was classified **RETRACTION**,
  which is the check being defeated by its own documentation. A second positive
  control catches it — plant the assertion *adjacent to the marker list* as well
  as far from it — and the standing rule is that **any hit inside the block
  documenting the census is read rather than classified.** The failure is
  contained (it can only ever excuse a hit, never invent one) but it fails in the
  direction that reports a clean tree, so it is stated rather than left for the
  next reader to rediscover.

  **And this is the companion to *a first failure masks its identical siblings*
  (#172), not a replacement for it.** Both are true and they fire in OPPOSITE
  directions: the sibling rule says a correction may have missed copies, so go
  looking — which is exactly what sent a lane looking here, correctly. This one
  says the looking will also turn up the correction itself. A count satisfies
  neither. **One correction does not find its own siblings, and one correction
  does not find its own FALSE POSITIVES either.**

  The reason this is a rule rather than a note about care: the three readers each
  knew the hazard, and one of them had written it down one paragraph above
  reporting the false positive. **A hazard that defeats people who know about it
  is a design problem**, and the fix that suggests itself — marking each quoted
  line so a line-oriented search cannot pick it up — was considered and REFUSED,
  because it optimises the file for `grep` at the cost of the reader, and the
  retraction being readable is the property that made the audit resolvable in the
  first place.
- **The verdict is still read from the output, for two reasons that are true and
  neither of which was the stated one.** `message(WARNING)` exits **0** on every
  version above while printing `CMake Warning`, so only an output verdict can hear
  a check that warns (#517) — which is why the pattern covers both words and why
  `script-check-warning-canary` is the half that proves the mechanism. And a check
  that shells out to another CMake without reading `RESULT_VARIABLE` exits 0 with
  its child's error on the output. `FAIL_REGULAR_EXPRESSION
  "${PACE_SCRIPT_CHECK_FAILED}"`, one spelling defined once in
  `src/tests/CMakeLists.txt`: a pattern restated per registration is one that
  drifts, and a drifted pattern stops matching without saying so.
- **A canary carried by its exit code is vacuous, and correcting the note is what
  exposed it.** A test fails when its exit code is non-zero **OR** the pattern
  matches, and `WILL_FAIL` inverts that whole verdict — so `script-check-canary`,
  a bare `message(FATAL_ERROR)` exiting 1, passed on its exit code alone and would
  have gone on reporting green with `FAIL_REGULAR_EXPRESSION` deleted from every
  registration in the tree. Measured under ctest, three cases: the old shape
  passes without the property, the new shape passes with it and **fails** without
  it. So the canary now exits **0** and prints a real `CMake Error` from a nested
  `cmake -P`, which leaves the pattern as the only thing that can fail it. That
  exit status is now load-bearing and therefore **asserted rather than
  remembered**: `check-script-check-signals` runs every `WILL_FAIL` registration's
  script and refuses a non-zero one, with a positive control refusing a scan that
  found no canary at all — otherwise "it exits 0" would be the next sentence
  somebody carries one clause too far. Fixing a wrong *reason* without re-deriving
  what it justified is how a guard survives as decoration.
- **A failure signal that is a property needs a canary and an omission check, and
  they answer different questions.** `script-check-canary` is a script whose only
  job is to fail, registered `WILL_FAIL TRUE`: it is green exactly while the
  mechanism works, and red the moment CTest stops honouring the property — naming
  the mechanism rather than whichever real check happened to have something to say
  that day. That covers nothing about whether a given registration *uses* the
  property, which is the far likelier failure and the one that reads as a working
  check; `script-check-signals` (`scripts/check-script-check-signals.cmake`)
  covers that, deriving the set of `cmake -P` registrations from
  `src/tests/CMakeLists.txt` rather than restating it.
- **A scan that attributes nothing reports nothing.** `check-script-check-signals`
  pairs each `-P` with the most recent `NAME` above it and **reports** a `-P` it
  could not attribute rather than skipping it: an unattributed registration means
  the scan lost track, and every verdict after that point was drawn from the wrong
  place. It also refuses to conclude when it matched no registrations at all.
- **Every `cmake -P` script declares `cmake_minimum_required(VERSION 3.28)`, because
  script mode declares no policies at all.** There is no project, so every policy starts
  UNSET and a policy-gated construct means whatever the CMake running it decides.
  Measured on 3.28.3 — the declared minimum and the version CI runs — against the same
  script with the declaration added:

  <!-- table-total: none -->
  | construct | policy | bare `cmake -P` on 3.28.3 | declared, or on 4.x |
  |---|---|---|---|
  | `if("b" IN_LIST haystack)` | CMP0057 | `CMake Error: Unknown arguments`, **exit 1** — errors before answering | answers |
  | `if(TRUE)` | CMP0012 | exit 0, `TRUE` read as a variable name, **branch NOT taken** | branch taken |

  **The half with no other remedy is the REVIEWER's machine.** CMake 4.x removed both
  policies, so the NEW behaviour is unconditional there and neither finding reproduces at
  all — a reviewer on 4.x reading one of these scripts is not testing what CI runs, and
  cannot falsify a claim about it. That is why the declaration is the fix and "reviewers
  should be more careful" is not: their tooling cannot see the problem. It happened both
  ways in one night (#497): a lane hit CMP0012 on 3.28 and the manager could not
  reproduce it on 4.3.1.
- **Under `ctest` these are LOUD; the silence is one level down.** Nothing in this tree
  passes `-Wno-dev` and `PACE_SCRIPT_CHECK_FAILED` is `"CMake Error|CMake Warning"`,
  so a registered check that trips a policy goes **red** on the 3.28 leg. What is silent
  is a **selftest's sub-run harness**: all six grep the captured output for `CMake Error`
  and none for `CMake Warning`, so a construct that merely warns and inverts is invisible
  there. That is where it actually bit — a #479 mutation warned, inverted, and scored as a
  successful red-proof of a case that had never been staged.
- **`script-check-signals` requires the declaration rather than enumerating the
  constructs.** The set of policy-gated constructs grows with every CMake release, so a
  guard that lists them is stale by construction. It walks the same registrations it
  already reads for `FAIL_REGULAR_EXPRESSION`, so the subject is derived and there is no
  second list. It lives there rather than in a check of its own because of the PARSER —
  a separate script would duplicate forty lines of NAME/`-P` pairing or restate the list.
  Not because "a new script would itself need the declaration", which sounds load-bearing
  and is false: it would be registered like every other check and covered by this pass. It matches `^cmake_minimum_required\(` anchored at line
  start: a word-match scored a file as compliant on the strength of a **comment saying it
  had none**, and returned 10 where the answer is 11.
- Do not "fix" this by raising the minimum to 3.29 and using
  `cmake_language(EXIT)`. The property works on every version, costs nothing, and
  is what makes the canary and the omission check possible; a version bump would
  buy an exit code and still leave nothing asserting that any given check can
  fail.

## A guard's stated BLIND SPOT is nobody's to re-derive, so it must name its DIRECTION

<!-- agent-tripwire: A guard's own stated BLIND SPOT is nobody's to re-derive, so it must name the DIRECTION it fails in -->

**Being blind to a MENTION is free. Being blind to a USE is the whole job.**

`pace_strip_comment_line` in `scripts/lib/CheckCommon.cmake` is the one comment stripper
for eight checks -- `check-test-loops`, `check-cli-text-cell`, `check-enumerator-walks`,
`check-istreambuf-iterator`, `check-markup-entities`, `check-ranges-seam`,
`check-selftest-registered`, `check-target-pragmas` -- so a defect in it is a defect in all of
them at once. Its header declared one, for as long as it existed:

> Still blind to either introducer inside a STRING LITERAL, as every regex-shaped reader here is.

That sentence is accurate and points the wrong way. It reads as a false POSITIVE -- a comment
inside a literal being stripped, which costs nothing and is what "as every regex-shaped reader
here is" is true of. The consequence was a false GREEN.
`src/apps/pacectl/SocketExchange.cpp:410` holds a one-line `std::format` request
literal whose header lines are separated by escaped CRLFs, one of them `Accept: */*`. The
three
characters `*`, `/`, `*` in `Accept: */*` contain a `/*`; no `*/` follows on that line; the
stripper entered a block comment and blanked the remaining **51 lines of the file**, a `for (;;)`
at line 420 among them. Every one of the eight checks then reported a clean count over lines it
had never read. The sibling shape -- a `//` inside a literal -- truncated **21 lines across 16
files**, losing text like `//") == 0)` and `"))`: in several cases the rest of a `REQUIRE`.
Closed in #1494.

**The ordering trap is that the paragraph eight lines below it in the same header describes this
exact failure** -- "every remaining line of that file was skipped while the caller still printed
a clean count over lines it never read -- a false green, in the one direction a check exists to
refuse" -- about a defect that had already been fixed three times, one step further in. Whoever
wrote the blind-spot note had the vocabulary and used it on the wrong half.

Three things to carry out of it, none of which is "read guards more carefully":

- **Ask a question the subject's own well-formedness answers, not a pattern census.** A C++ file
  that COMPILES cannot end inside an unterminated block comment, so *does the stripper leave one
  open at EOF* has no false positives at all. Exactly one file of 915 did, and it was the one.
  A grep for `/*` inside quotes would have produced a list to argue about instead.
- **A self-test written for what a stripper REMOVES passes under the entire defect.** Every
  assertion about removal is satisfied by a stripper that removes too much. Assert what
  SURVIVES, and prove the cases can fail by neutering the library: each case in
  `check-comment-stripper-selftest.cmake` is green over a function that returns its input
  unchanged, so six neuters are what make the table mean anything, and a neuter that provokes
  nothing is reported as the self-test's own failure.
- **A fix's own REACH is part of the fix.** `'` is deliberately not a literal opener here: 262
  lines of this tree are digit separators (`1'000'000`), so treating a quote-shaped character as
  a char literal would blank the tail of twelve times as many lines as the defect ever touched.
  A `'"'` therefore opens a literal that usually does not close on its line, and an unterminated
  literal KEEPS the rest of the line rather than dropping it -- the fail-CLOSED direction, since
  a finding somebody can see and exempt beats a clean report over text that was dropped. Both
  limits are pinned by cases so they stay decisions rather than becoming discoveries.

## A guard's REMEDY TEXT is part of the guard

<!-- agent-tripwire: A guard's REMEDY TEXT is part of the guard. Nothing tests it, and it is the only part of a check most people ever read -->

**Nothing tests it, and it is the only part of a check most people ever read.**

A check's verdict logic gets a self-test, a canary, a neuter-and-watch-it-fail pass. The
paragraph it prints when it refuses gets none of that — and that paragraph is the entire
interface for whoever trips it, who is by definition somebody who does not know the rule
yet and has just been stopped by a tool they did not know existed.

`check-catch-skip-return-code`'s refusal ended (#1128):

```
That is a false RED on any runner where an environment-conditional skip
fires -- and it teaches whoever meets it that the SKIP was wrong, rather
than the registration. Add to the registration:

    catch_discover_tests(<target> PROPERTIES SKIP_RETURN_CODE 4)
```

after the same commit made `SKIP_RETURN_CODE` the thing the check REFUSES. **The remedy
instructed the reader to reintroduce the defect the check exists to prevent.** They would
have applied it, hit the identical refusal, and concluded the check was broken — which is
the reading that gets a guard deleted. Worse than a silent guard: a guard steering people
into the defect while sounding authoritative.

- **It survives every test a check normally gets.** The verdict logic was correct
  throughout; ten synthetic trees drove it in both directions and all ten passed. The
  self-test asserts THAT the check objected and, at most, that it named the right file —
  never what it advised. There is no arrangement of tree fixtures that catches this,
  because the text is right where the code is wrong is not the failure; the code was
  right and the text was wrong.
- **The window is a change of MECHANISM, not a change of verdict.** Nobody forgets to
  update a message when a check starts refusing something new — the message is why they
  opened the file. It rots when the check goes on refusing the same SHAPE for an
  opposite reason, so the diff touches the predicate and the paragraph three hundred
  lines below it still parses as true.
- **Read the refusal as the person who has never seen it.** Not "is this sentence
  accurate" but "if I did exactly what this says, where do I end up". Those are
  different questions and only the second one found this.
- **Say what the rule does NOT cover, in the refusal itself.** The same message now
  states that the script-driven `SKIP_RETURN_CODE 77` registrations are unaffected —
  a shell script chooses its own exit code and a Catch2 binary does not. Without that
  clause the next reader over-applies the refusal
  and deletes a property that is load-bearing somewhere else, which is the mirror
  failure and just as expensive.

Same family as [a rulebook entry that has gone false](#a-rulebook-entry-that-has-gone-false-instructs-the-next-person)
and as a comment naming the wrong guard: text that instructs, is trusted, and is checked
by nothing. This one is narrower and sharper, because a check's own output carries more
authority than either — it arrives at the moment of failure, from the tool doing the
refusing.

## The Windows Debug leg exists for the RUNTIME, and proves it is live

<!-- agent-tripwire: A Windows **Debug** leg is run for `_ITERATOR_DEBUG_LEVEL=2`, not for the compiler -->

`build.yml`'s Windows matrix ran `cl-release` and `clangcl-release` only, so the
one Debug configuration on Windows was never built in CI — while being the default
preset every developer here debugs with. A `cl-debug`-only defect could therefore
live on master indefinitely with every status check green (#315).

- **The value is `_ITERATOR_DEBUG_LEVEL=2`, not the compiler.** MSVC's Debug CRT
  traps invalidated iterators, out-of-range indexing and mismatched container
  iterators *at the point they happen* — the class a Release build tolerates in
  silence and a sanitizer would otherwise have to find. So the leg runs `ctest`;
  a Debug leg that only compiles exercises none of what it was added for.
- **Nothing in this project states that level, which is why it is asserted rather
  than assumed.** It follows from `_DEBUG`, which follows from the runtime library
  flavour, which follows from `CMAKE_BUILD_TYPE` and `CMAKE_MSVC_RUNTIME_LIBRARY`.
  Any of those moving removes the checks with no warning, and the leg would still
  build, still run the suite, and still report green. `iterator-debug-canary` is a
  program that must die, and `scripts/iterator-debug-gate.ps1` refuses a build
  where it survives — the same answer as `tsan-canary`, deliberately the same
  shape rather than a second idiom.
- **A non-zero exit is not proof.** The gate requires the runtime's own
  `subscript out of range` diagnostic, exactly as the TSan gate requires
  `data race`: a canary that died of something else is a canary proving nothing.
- **The canary's CRT report modes are set before it runs**, and that is load-bearing
  rather than defensive: an unhandled debug assertion pops a modal dialog, and on a
  runner that means the job hangs to its timeout instead of failing in a second. It
  used to set them in its own `main`, as every program here did -- which is exactly
  why four test binaries on `Catch2::Catch2WithMain` set nothing. The build now
  attaches one translation unit to every executable instead; see
  *No executable raises a modal error dialog* below (#1389).
- **A third leg rather than replacing a Release one, and that was measured.** No
  Windows leg is the longest job in any sampled pull-request run, so this leg costs
  runner-minutes and no wall clock, and giving up a Release configuration to buy
  that would trade coverage for capacity already there. The per-leg figures are
  *What CI costs* below and are not restated here — the last two written down in
  this spot went stale twice over, once when `SCCACHE_GHA_ENABLED` landed and again
  when the matrix grew a third leg, and both times they read as current fact. So
  does "`clang-tidy` finishes last", which has now gone stale a third time and in
  the other direction, #554 having diff-scoped the queue's sweep. Which job is
  longest is the last column of the table in *What CI costs*, per event; this
  paragraph deliberately no longer says what it holds.
- **Guarded to `MSVC AND CMAKE_BUILD_TYPE STREQUAL "Debug"`, which means its
  absence elsewhere is normal.** That is worth knowing before debugging it: a
  platform-guarded registration is indistinguishable from a lost one when you look
  at a single platform's `ctest -N`. Check a listing where it *should* be missing
  and one where it should not, and confirm a neighbouring test is still present.

### No executable raises a modal error dialog, and the BUILD installs that, never each `main` (#1389)

A failed `assert()`, an iterator-debug check or an `abort()` in a Debug CRT opens a dialog
and waits for a click. That does not fail a test: it hangs it, to ctest's `TIMEOUT` on a
desktop and to the job's limit on a runner, where it reads as a slow job. An `endo` test
hung 58 minutes that way.

`src/tests/WindowsErrorPopups.hpp` already knew how to switch it off. What it could not do
was reach a `main` this project did not write: it was the first statement of every `main`
here, and four test binaries link `Catch2::Catch2WithMain`, so they set nothing.

- **So the build attaches it, the way `cmake/Utf8CodePage.cmake` attaches the UTF-8
  manifest.** `cmake/ErrorPopups.cmake` walks every executable under `src/` and `vendor/`
  and adds `src/tests/ErrorPopupsAtStartup.cpp`, whose constructor runs in the
  `init_seg(lib)` segment: after the CRT's own initialisation, before every user static
  initialiser, so an object that asserts while it is constructed is covered too. The
  per-`main` calls are gone. A second mechanism for one property is how the copies drifted
  last time.
- **What proves it is the ARTEFACT, not the walk.** `ctest -R error-popup-coverage` reads
  the walk's manifest, every `CTestTestfile.cmake` and `build.ninja`. An executable counts
  as launched when its path appears in a registration -- as the command or as an argument a
  script is handed -- or a `catch_discover_tests` include file carries its name. It is
  covered when this configuration's link edge names the object. It refuses a launched
  executable that is neither covered nor exempt, and it refuses whenever it cannot ask:
  no manifest, an empty one, or an anchor that is not proven. A target defined after the
  walk, or outside its roots, is exactly what it catches, and no `CMakeLists.txt` would
  read wrong. **The census is NOT taken through the walk**: its first version was, and
  dropping `vendor` from the walk's roots left the check green over an unsuppressed
  `pace-tui-tests`, the vendored TUI's test binary while there was one -- a list derived by the thing it checks is exact about what that
  thing reached and silent about the rest. It is taken at the end of configure over the
  whole source tree; measured since, the same neuter is refused by name, and so is moving
  the walk ahead of `src/tests`.
- **The runtime is asked separately.** `error-popup-canary` links `Catch2WithMain` on
  purpose and fails a Debug assert. Its gate requires the process to END, with the
  assertion's own text, inside a bound. Measured at `1151a588`, in `cl-debug`: with the
  object, exit 3 in under a second. With it removed, the process was alive after five
  seconds and owned a visible window titled `Microsoft Visual C++ Runtime Library`, and
  the gate refused at 60 s. **The assertion text was on stderr in BOTH runs** -- the dialog
  held the process after the text was written -- so a gate that read only the text would
  have passed the hang. It checks the process ENDED first.
- **Product binaries count, because tests spawn them**: `pace-kv`, `pace-cc`,
  `pace-node` and `pacectl` are all handed to e2e scripts, and the
  check finds them through those arguments. **But a product binary suppresses only when
  asked**, by `PACE_SUPPRESS_ERROR_DIALOGS` in its environment: a developer running a
  Debug `pace-kv` by hand keeps the dialog and the debugger it offers, which is what a
  Debug build is for. The first draft here suppressed in every Debug product binary and
  took exactly that away. **Every registered test sets the variable**, so a binary a
  fixture spawns inherits it: a deferred walk sets it on each `add_test`, and each
  `catch_discover_tests` names `PACE_ERROR_DIALOG_ENVIRONMENT` itself, because its
  registrations do not exist at configure time. The check reads both kinds of generated
  registration and refuses a test that does not set it. `error-popup-product-canary` is
  built as a product binary is, and its gate requires both directions -- routed to a file
  with the variable, left on the dialog without -- since either alone is satisfied by a
  wrong policy. It REPORTS the assert report mode rather than asserting, so the
  unsuppressed direction opens no dialog on a desktop and proves something on a runner that
  has none. This is the mechanism `endo` proved.
- **An exemption is a reason on the target itself**, never a row in a list:
  `set_target_properties(<t> PROPERTIES PACE_ERROR_POPUPS "<why>")`. The walk skips
  it and the check prints the reason. Nothing is exempt today.
- **Not covered, and not this project's to cover**: a program the build does not define.
  The compilers the launcher spawns, `pwsh`, `git` and `cmake` itself are not in the
  manifest and are not checked.

## What CI costs

<!-- agent-tripwire: A ccache hit does NOT skip clang-tidy: the launcher and the analyser are two independent commands -->

The workflow's *critical path* is the longest single job, and for a long time that
was one job: `clang-tidy`, at 28.6 minutes out of a 28.6-minute workflow (run
`33243524509`, master, green). The bullets whose figures name that run were
measured on it, and the numbers are kept because each one is the reason a knob is
where it is.

**A CI figure without its EVENT is not a figure.** This one workflow costs three
different things depending on what triggered it, and the longest job is a
different job in each — so "the critical path is N minutes" is answerable only
once you say which. Measured over 99 completed, green `build.yml` runs between
2026-09-01T09:28Z and 2026-09-02T19:03Z, on the three-leg Windows matrix, with
`SCCACHE_GHA_ENABLED` in force; runner-minutes sum the non-skipped jobs, run wall
clock is the last job's end minus the first job's start, and job durations come
from `repos/:owner/:repo/actions/runs/:id/jobs` rather than from impressions.
Some of the bullets below quote **step** timings, and those come from separate
samples taken on 2026-09-02 — how far they overlap these 99 runs was not
recorded, so do not reconcile a step mean against a job range below to the tenth.
**Every one of these figures is the state BEFORE the merge-queue sweep was
diff-scoped**, which is the bullet three below and is what makes them worth
re-measuring rather than citing forward:

<!-- table-total: none -->
| event | runs | runner-min, mean | longest job, mean | run wall, mean | which job is longest |
|---|--:|--:|--:|--:|---|
| `pull_request`, code-touching | 36 | 102.7 | 19.0 | 24.1 | `clang-tidy` (18 of 36) |
| `pull_request`, docs-only | 7 | 0.6 | 0.1 | 1.1 | — (7 jobs, none over 10 s) |
| `merge_group` | 33 | 113.6 | 23.5 | 31.7 | `clang-tidy`, full sweep (32 of 33) |
| `push` on master | 23 | 109.8 | 22.7 | 27.0 | `clang-tidy`, full sweep (23 of 23) |

**Runner-minutes and wall clock are different questions and the answer differs by
which you asked.** Landing one code change costs **326.1 runner-minutes** — the
`pull_request` code-touching row plus `merge_group` plus `push`, named rather than
counted off by position, since the docs-only row sits between them and a reader
following "the top two rows" arrives at 24.1 + 1.1. Only the first two of those
three are on the path from "ready" to "merged", because the master `push` fires
AFTER the merge. So the CI wall clock a contributor waits through is
**24.1 (`pull_request`) + 31.7 (`merge_group`) = 55.8 minutes**, and the push's
109.8 runner-minutes buy **zero** merge latency. A lever that removes cheap
parallel jobs buys minutes and no latency; one that shortens the longest job buys
both. Say which you are selling.

The other thing the older figures did not carry: **on a pull request the sweep is
bimodal, not average.** Over 19 pull-request sweeps whose per-STEP timings were
pulled — a subset of the 36 runs above, because the step sample was collected
separately and is not the row's denominator — 11 were diff-scoped (0.0–8.4 min) and
8 escalated to a full sweep (21.8–25.5). That 8-of-19 escalation rate and the row's
`clang-tidy`-is-longest count of 18-of-36 are two different questions over two
different samples and do not have to agree; neither is the other's check. The mean
of 12.8 describes no run in either, and any prediction from it is a prediction about
a run that does not happen — including the projection three bullets below, which
makes it anyway and says so there.

- **The `push` on master is LOAD-BEARING, and it is the only full `clang-tidy`
  sweep left.** It reads like the workflow's most obviously redundant run and was
  documented that way until #554; the bullet below is that case, kept because the
  measurements in it are still true and still the reason the trigger is shaped as it
  is. What changed is not a number: the merge queue now diff-scopes its sweep
  against its own `base_sha`, and *what makes that sound* is that master@N was
  proved fully clean by the push that landed it. Narrowing `on: push` to tags would
  therefore now remove the analysis every other run's scoping rests on, on top of
  freezing the cache scope only a push writes. It has TWO unique products, not one.

- **The `push` on master otherwise rebuilds a tree the merge queue has already
  proved, and its other unique product is a handful of cache entries.** A
  `merge_group` run and the
  `push` on master that follows it carry the *same* `head_sha` — 6 of 6 pairs
  checked on 2026-09-02 — so the master push recompiles, retests and repackages a
  tree the queue has already proved green. That is a whole bottom row of the table
  above, per merge. Measured on the docs-only #530: **0.5** runner-minutes at
  pull-request time, which is the scoping working, then **108.9 + 95.0** to land
  it.

  Per *merge* that is a doubling, and only at a queue **batch of one** — which is
  what this repository has had, and is the condition on those six pairs. GitHub
  batches queue entries, and a batch of N dispatches N `merge_group` events and
  lands as ONE push, so the ratio is `(N + 1) / N` and the per-merge price falls as
  batches grow. The duplicated *run* does not: there is one redundant full matrix
  per batch whatever N is. `build.yml`'s `changes` job already records the batching
  from the other side.

  It is not pure waste, and the difference is measurable rather than argued.
  *Measured*: on the same `head_sha` the queue run had just compiled, each Windows
  leg of the master push still took **6–7 sccache misses out of 668 requests** —
  it re-stored objects the queue run had already built and cached. *Inferred*, from
  GitHub's documented cache scoping rather than from an experiment here: a run
  restores from its own ref and from the default branch, and writes only to its own
  ref, so the queue's `gh-readonly-queue/master/…` entries are unreachable by
  anything and the master push is what publishes those objects for every later pull
  request and queue entry to restore. Narrowing the push trigger to tags — NOT
  deleting `on: push`, whose `tags:` row is the only way the `release` job is ever
  reached — would therefore trade a bottom-row run per merge for a cache that goes
  cold at whatever rate master changes: a real trade, not an obvious one. **A third
  measurement, 2026-09-02**: `refs/heads/master` holds **2521 cache entries
  totalling 7.9 GB**, and no other ref can be written to it — the inference above
  confirmed from the `actions/caches` listing rather than from the documentation. It
  says how much would go cold and not how many minutes that costs, so the *size* of
  the second half is still unpriced; what settles the trade today is the bullet
  above it rather than this number.

- **A pull request and a merge-queue entry diff-scope the `clang-tidy` sweep;
  every other event sweeps everything, which today means the master `push`.** The
  step was `--all` for every event but a pull request, so the workflow's critical
  path was the same full sweep three times per landed change. Measured on the 99-run
  sample above: the `Sweep` step costs **22.50 min** in the queue against **12.80**
  on a pull request, in a job whose remaining steps — checkout, apt, configure, the
  scope self-test — come to about **a minute**. So the sweep *is* the job, and the
  queue was paying for the same 497 translation units the push was about to walk
  again. That last figure is a difference between a job mean and a step mean drawn
  from two samples, which the header of this section says not to reconcile to the
  tenth; it is quoted to an order of magnitude for that reason and nothing rests on
  its precision.

  Applying the pull request's scoping to the queue takes it from 113.6 to **104.0**
  runner-minutes, its longest job from 23.5 to **15.0**, and its wall clock from
  31.7 to **24.5** — which is **55.8 → 48.6 minutes of merge-path wall clock**, the
  only lever anyone has found that moves that number by more than a couple of
  minutes. Per change, 326.1 → 316.5 runner-minutes.

  **Those four numbers are the prediction this section forbids, made deliberately
  and with its bias named.** They substitute the pull request's 12.80 sweep mean
  into the queue, and that mean describes no run: the distribution is bimodal, so
  the queue after this change is a mixture of ~1-minute entries and ~23-minute ones,
  not a population of 15-minute ones. The bias has a direction, and it is
  optimistic — a queue entry can batch several pull requests and escalates if *any*
  member touches a `SweepEverythingWhen` path, so its escalation rate is at least the
  pull request's 8-of-19 and 12.80 is an under-estimate for it. It is used because
  nothing better exists before the change lands. **Re-measure after merging**; until
  then read these as a direction with a floor, not as figures.

  **What it stops checking, and where that is still caught.** In the queue: findings
  in translation units the change cannot reach. Still caught by the master push's
  `--all`, and the union is complete — master@N proved fully clean, plus a scope
  that over-approximates everything a change can reach, covers master@N+1.

  **Both halves of that are wiring, and wiring is asserted** (`ctest -R
  tidy-sweep-scope`). Take the `--all` off the push and every run in this repository
  stays green while the analysis is permanently narrower than this bullet claims:
  no failing check, no slower job, no log line, just a confident count over fewer
  translation units — the failure `tidy-sweep.sh` exists to prevent one level down,
  reached one level up. Delete the report step and the full sweep still runs, still
  fails and still reaches nobody. So the check reads the workflow for four things:
  that the sweep step **consults the mapping** (`--ci`) and restates none of it;
  that the queue entry's own `base_sha` reaches that mapping **under the
  environment name `tidy-sweep.sh` reads it from**, which the check takes from that
  script rather than restating — matching only the expression cannot see a rename,
  and a rename is the one edit that breaks the wiring while leaving the expression
  in place, silently, in the direction where the queue diffs against master; that
  some step reads
  the sweep STEP's conclusion for `refs/heads/master`; and that the job grants the
  `issues: write` without which that reader is decorative.

  **The mapping itself is one table**, `CiScopeTable` in `scripts/tidy-sweep.sh`,
  driven by that script's own `--self-test` (#570). It was two GitHub expressions —
  a `BASE:` env expression and an `--all` argument expression — composed with the
  shell inside the script, so "what happens on event X" had to be read out of two
  languages, and nothing stated it. The reader's `if:` is a third per-event
  expression in that workflow and deliberately did **not** move: it decides who is
  TOLD about a failure rather than how wide the analysis is, and rule C still
  checks it where it stands. The
  workflow now hands over the three FACTS its context holds
  (`GITHUB_EVENT_NAME`, `GITHUB_BASE_REF`, `MERGE_GROUP_BASE_SHA`) and decides
  nothing, which is why the check's first rule is now *do not decide here* rather
  than *spell the guard this way*.

  That respelling is not a tidy-up, and what it preserves is worth keeping written
  down. The old guard had to EXCLUDE the two diff-scoped events rather than NAME
  the event that gets the full sweep: `event_name == 'push'` and `event_name !=
  'pull_request' && event_name != 'merge_group'` select the same events today and
  fall opposite ways tomorrow — a trigger added to `on:` later diff-scopes under
  the first and sweeps everything under the second, and on master a diff-scoped run
  has an EMPTY diff, so `tidy-sweep.sh` prints `no source changed` and exits 0
  having analysed nothing. Narrowing silently is the failure; re-widening is merely
  slow. A table with a **default row** is that property made structural: the events
  that diff-scope are listed, everything else falls to `all`, and there is no
  spelling left to get backwards. The paragraph this replaces said the reverse of
  the old rule until a review caught it, which is worth leaving recorded, because
  an agent reading this file before touching the area would have rewritten the
  guard on its authority and been failed by the check.

  Each rule is driven red on a GENERATED workflow by `--self-test`, in both
  directions, because a guard nobody has seen bite has told you nothing. Generated
  rather than sed-edited: the first shape edited a correct fragment with
  `/pat/,+2d`, a GNU extension BSD sed rejects, and checked no exit status — so on
  macOS the edit failed, the fragment came out empty, the check failed because
  there was no workflow at all, and the case printed `ok` for a break it had never
  staged. Every case now also asserts its fragment DIFFERS from the correct one, so
  a knob that does nothing fails instead of passing. Two cases run the other way and
  assert a pure REFLOW is not read as a deletion — the `run:` block collapsed to one
  line, the reader's `if:` wrapped as a folded scalar — because a red build accusing
  an author of deleting the sweep they only reformatted is worse than no check.

  **The residual is narrower than it first reads, and the narrowing is the part that
  matters.** A clang-tidy finding depends on a translation unit's own sources and its
  include closure, both of which the scope covers; `SweepEverythingWhen` covers the
  changes that alter how every unit is read. So a *code change* plants a finding
  outside its own scope only where the scope under-approximates, and `tidy-sweep.sh`
  names its one such direction in its own header: an include spelling that resolves
  to no first-party file is taken for a system header and dropped. That is a real
  gap and it is not new — the diff-scoped pull-request sweep has always had it — but
  it is why this reads "only where the include graph is complete" rather than "never".

  What was left beyond that was the analyser drifting under us — apt.llvm.org publishing
  a new `clang-tidy-22`. Since #1404 it cannot drift: the analyser is the PyPI build
  `.clang-tidy-version` declares, identified before every sweep, and changing that file is
  itself a `SweepEverythingWhen` row, as `build.yml` is for `CLANG_TOOLS_VERSION`. Before
  that, the diff-scoped PULL REQUEST sweep caught drift only where it landed inside the
  scope it already swept. Drift therefore surfaces at the master push, and failing that at the next
  pull request whose change escalates — 8 of 19 sampled, so hours rather than weeks.
  It is a check that MOVED, not one that was lost.

  **Evidence the escalation was not paying, honestly bounded.** Four `merge_group`
  `clang-tidy` failures in the window (`1312bc6c`, `45760033`, `d04bb8ab`,
  `f77f4fbf`). All four are one root cause — a batch that was pairwise clean and
  conflicted serially, `FrameEndpoint_test.cpp: no viable conversion from
  'chrono::seconds' to 'DialOptions'` — and at each of them **13 other jobs failed
  too**, every Linux, Windows and macOS build among them. So in this sample the full
  sweep caught nothing the ordinary builds did not. Four failures with one cause is
  not a proof that it never pays, and it is not offered as one.

- **A master push blocks nothing and reaches nobody, so moving a check onto it means
  putting a reader on it.** Checked three ways on 2026-09-02, all negative: every one
  of the last 30 master-push runs was triggered by `github-merge-queue[bot]`, so
  GitHub's failure mail goes to an app account with no mailbox; nothing under
  `.github/` sends a notification of any kind; and **all 18 failed master-push runs
  back to 2026-06-10 sit at `run_attempt: 1`**, never once re-run. That last one is
  not proof nobody read them, and it is 18 for 18 of nobody acting.

  **And the remedy does not get to skip that test.** An issue opened by
  `github-actions[bot]` reaches a person only if somebody queries the label —
  GitHub's default "Participating and @mentions" does not notify on a bot-opened
  issue — so the reader this bullet installs is *asserted*, on the same evidence
  standard the bullet just refused to accept: none. It is a strictly better place
  for the signal than a run log nobody opens, because `status/needs-triage` is a
  query this repository already runs, and it is not a measured improvement. If the
  issue sits untouched, that is the same finding one level up and the answer is a
  louder channel, not a second unmeasured one.

  So the sweep's own failure opens or updates one issue — and the shape of that is
  the whole point. It keys on `steps.sweep.conclusion` **in addition to** the
  `failure()` status function, never on the job's result alone; `failure()` is not
  redundant and removing it gives a step that never runs at all, because GitHub
  skips every step after a failed one unless a status function says otherwise. **Over those same 18 failed master-push runs** — one window, one
  denominator — a notifier on any failing job fires **18 times**, and `clang-tidy`
  was the failing job in exactly **one** of them. The margin is wider than that one
  suggests, and the direction is worth having exactly rather than roughly: in that
  single run the failing STEP was `Test`, in the job's pre-split shape, so the
  step-keyed condition that ships here would have fired **zero** times across the
  whole window. 18 against 0, not 18 against 1. That is the whole comparison; a rate
  over "push runs" would need a third window and is not what decides it, and what
  those 18 failures were *about* was not classified run by run — the count is what
  the argument rests on, not a characterisation of the causes. The test a new alarm
  has to pass here is whether a firing means something happened, which is the test
  that withdrew a counter in #447.

  Zero firings is also the weaker half of the evidence and is not offered as more:
  it says the alarm is quiet, not that it is sensitive. What makes it sensitive is
  that the condition was watched firing on a forced failure (PR #561, run
  `33677107395`) with a negative control keyed on a passing step skipped beside it.

  One OPEN issue, updated by comment — the lookup is `--state open`, so a report
  somebody closed is not found and the next failure opens a fresh one. That is
  wanted (a closed report means it was dealt with) and is not what "reopen" would
  promise, so the word is avoided: commenting on a closed issue does not reopen it.
  Keyed on the **title**, read out of a `--label`
  listing rather than a `--search`: search goes through GitHub's issue index, which
  lags creation, so two master pushes failing inside that window would each find
  nothing and each open one. The labels are `CONTRIBUTING.md`'s own — a private
  `ci/…` key would be a label every documented filter is blind to — and
  `status/needs-triage` is applied by the step rather than left to
  `issue-triage.yml`, which never sees this issue: an issue opened with
  `GITHUB_TOKEN` triggers no workflow, so the repository's one reader-attachment
  mechanism does not fire and the report would land outside every triage query.

  It is a STEP inside the tidy job rather than a job of its own, and that is forced:
  `check-release-gate` asserts every job in the file appears in `release.needs`, and
  a job that is skipped on a tag push — which any push-failure notifier is, always —
  skips `release` with it. That is this file's never-arrives failure aimed at the
  release instead of at a required context.

- **A ccache hit does not skip clang-tidy, so caching harder was never the fix.**
  That job reported **535 hits out of 592 cacheable calls (90.4%)** and its build
  step still took **23.8 minutes**. CMake wires the analyser in through
  `cmake -E __run_co_compile`, which runs the compiler behind its launcher and the
  analyser as two independent commands: a replayed object buys the compile back and
  not one second of the analysis. The only way to pay less clang-tidy is to run it
  over fewer translation units, which is why the job stopped building at all and
  became `scripts/tidy-sweep.sh` over a compile database.

- **The sweep's scope is the diff plus everything the diff can break, and every
  way it can be wrong errs towards sweeping more.** A changed header is not a
  translation unit: tidying only the changed `.cpp` files would let one edit to
  `Logger.hpp` land findings in seventy files nobody checked, and the sweep would
  print a confident count while doing it. So the scope is the changed `.cpp` files
  **union** every `.cpp` that transitively includes a changed header — resolved by
  longest path suffix, so an ambiguous spelling reaches every candidate and an
  unresolvable one is dropped as a system header. An over-approximation costs
  minutes; an under-approximation costs a red master for code a pull request was
  told was clean. A base ref that does not resolve escalates to the full sweep for
  the same reason: "we could not tell what changed" must never read as "nothing
  did". Measured on this tree: a leaf `.cpp` sweeps 1 unit, a mid-level header 23,
  `Core/Logger.hpp` 71, and a `.cmake` all 329.

- **A change that decides how EVERY translation unit is read escalates to the full
  sweep, and that is a table** (`SweepEverythingWhen`): `.clang-tidy`, any
  `CMakeLists.txt`, any `.cmake`, `CMakePresets.json`, `vcpkg.json`, `*.hpp.in`
  (it generates a header the include graph cannot see), the sweep script and the
  workflow. A README typo is deliberately not on it.

- **The unit of work is a compile command, not a file, and that is what makes the
  swap lossless.** `Stats.cpp` builds into `pace-cc`, `pace-cc-tests`
  and `pace-node`, which do not agree about `PACE_COMPRESSION_ENABLED`.
  `clang-tidy -p <dir> <file>` does **not** take the first matching entry:
  libTooling's `ClangTool::run` loops over *every* command the database returns for
  that file. So a file with one command needs nothing special, and a file with
  several is served **only** by one single-entry database per command — handing it
  to the shared database *as well* analyses each of its commands twice.
  Measured against a CI-shaped database: 594 entries, 445 of them first-party, and
  329 distinct files — so a per-file sweep would have stopped checking a quarter of
  what the build checked. 445 is also exactly what the old job tidied
  (`include(ClangTidy)` runs *after* the `CPMAddPackage` calls, so a fetched
  dependency's targets never carried `CMAKE_CXX_CLANG_TIDY`), which is the sense in
  which this change costs no coverage. Measured scopes on that database: a leaf
  `.cpp` 1 unit, `Distributed/SchedulerService.hpp` 29, `Core/Logger.hpp` 83,
  `Stats.cpp` 4 (one file, four commands), a `.cmake` all 445, a README nothing.

- **The translation units come from the compile database, never from
  `git ls-files`.** `IocpReactor.cpp` is a translation unit on Windows and a file
  on Linux, so a full sweep taken from the index would fail on sources no target
  here builds — and a diff-scoped one would report findings for a compile command
  that does not exist.

- **But *first-party* means git tracks the file, and that is a definition rather
  than a list of directories.** A fetched dependency's sources are compile-database
  entries like any other — Catch2, yaml-cpp and lz4 are ~150 of the 594 entries here
  — and **where they land is configuration**: `_deps/` under the build tree by
  default, `$CPM_SOURCE_CACHE` anywhere, which in CI is `.cache/CPM` *inside* the
  workspace. An exclusion written as a path (`/_deps/`) was measured to let all
  ~150 of them through under CI's own layout, which turns a full sweep into a
  failure inside lz4's `xxhash.h`. Intersecting with
  `git ls-files --cached --others --exclude-standard` gets it right wherever the
  cache is put, and subsumes the absolute-path and out-of-tree cases for free.
  `--others` is in there deliberately: a source created and not yet added is
  exactly the code nothing has ever checked.

- **A database generated for clang-tidy needs `CMAKE_CXX_SCAN_FOR_MODULES=OFF`
  named explicitly, even though `CompileCache.cmake` sets it.** That module turns
  the scan off only when it *picks a launcher*, and the tidy job installs no ccache
  for it to pick. Without the flag every compile command carries `@…modmap`
  arguments that do not exist until the target is built, every translation unit
  fails to parse, and the sweep reports clean having checked nothing — which is the
  exact failure `scripts/tidy-sweep.sh` canaries against, so it is caught rather
  than believed.

- **And it must be configured with the same *target set* CI builds.** Its sibling
  above is about a database whose commands do not work; this is about a database
  that is missing commands, and it fails in the opposite direction — quietly, with a
  number attached. A sweep whose scope is derived from a database is only as complete
  as that database's target set, and **a target gated off by default is invisible to
  the sweep rather than absent from CI**: the option table's default is what the
  local `cmake` line inherits, and the workflow's own `-D…=ON` is what CI builds.
  Those two disagreeing is not a misconfiguration anybody would notice, because both
  sides are behaving as written. Measured on a review sweep here: a database
  configured with the defaults produced **15** translation units for a diff that CI
  tidies as **20**. The five were the launcher-facing sources reachable only through
  the two default-OFF app targets, and every one of them was inside the change. The
  sweep does not error on them — they simply are not in the file list, and it prints
  a confident count of what it did check.

  And **the script cannot catch this for you**, which is why it is a rule and not a
  guard. `tidy-sweep.sh` drops a changed file with no compile command silently, and
  it is *right* to: the bullet above requires exactly that, because `IocpReactor.cpp`
  in a diff on Linux is a file this platform does not compile and must not fail the
  sweep. Absent-because-this-platform and absent-because-that-target-is-off are
  indistinguishable from the file list alone. Only a full plan of zero units is
  fatal, and under-covering by five of twenty is not that.

  So the check belongs to whoever configures the database, before running it:
  compare the units the sweep reports against `git diff --name-only origin/master...HEAD`
  and account for **every** file it did not reach. The answer is either "this
  platform does not compile it" or "I configured the wrong target set" — and when
  adding an app target the question is never "is it built by default" but "does any
  CI job build it", because if yes its flag belongs in whatever line generates a
  database.

  **A file the sweep DID reach can still be uncovered, and that half is now the
  script's** (#466). A translation unit whose file is guarded out to nothing has a
  compile command, so it never meets the drop rule above — it is planned, analysed,
  reported clean, and the clean report is the defect: `TlsSocket_test.cpp` carried a
  syntax error while the database listed it, clang-tidy passed it, both compilers
  built it and ctest ran a binary holding none of its cases. Five signals agreed
  about nothing. So the sweep preprocesses each unit once more and reports
  **contributed / produced no code in this configuration / could not be
  preprocessed**, per FILE, since a file has several commands and they need not
  agree. There are now **two** lists to reconcile against the diff, not one, and the
  headline counts files rather than commands. An empty unit is a guard working and
  is never a fault — the leg where that guard is ACTIVE is what covers the file, so
  the reconciliation is against the matrix, not against this run.

  What the script still cannot answer is whether any CI leg compiles it with the
  guard active. That is a different instrument over the matrix, and it is the half
  with teeth: this one reports, and a green job's log is not read.

  **The half with teeth is `scripts/tidy-blind-spots.txt` and the check over it, and
  it is TWO registrations because it is two questions.** The MEASUREMENT reads the
  compile database, the objects and `nm`, so `tidy-blind-spots` runs on Linux with
  ASan and TLS on and nowhere else — and a registration that exists in one
  configuration reports nothing in every other, which reads like a pass. So the
  table's own rules — every reached-by column names a clang-tidy leg the workflow
  still has, every row carries a REASON — are `tidy-blind-spots-table`, in the
  default set, on every platform, needing no build; and `conditional-check-reach`
  derives the option-gated registrations in `src/tests/CMakeLists.txt` from the
  `if()` nesting around them and asserts some `build.yml` job still configures a
  build each one can run in AND runs `ctest`. Neither names `tidy-blind-spots`: both
  DERIVE it, so a flag change on either side refuses rather than silently shrinking
  the set (#589).

  **Two things about the shape of the instrument that is still missing, both of
  which cost a wrong design once.** It is a check over **guards**, not over
  platforms: `TlsContext_test.cpp` and `TlsSocket_test.cpp` are guarded out by a
  build OPTION and not by an OS, so a platform-keyed check answers a question
  narrower than the one asked. And its union is over **(leg × configuration)**,
  never over legs — a leg that builds with an option OFF has run without covering
  anything that option gates, so counting it as coverage is the same over-report one
  level up. Which units are reached by no leg at all is a number this check prints on
  every run, and closing it is [#858](https://github.com/LASTRADA-Software/pace/issues/858).

- **The sanitizer test run moved to `clang-asan-ubsan`; it did not go.** The
  `clang-debug` preset is the only configuration in the workflow with ASan and
  UBSan on, so that job's `ctest` is the project's entire sanitizer coverage in CI.
  It keeps the `clang-debug` preset with `-DENABLE_TIDY=OFF` rather than switching
  to the identically named `clang-asan-ubsan` preset, which does not set
  `PEDANTIC_COMPILER_WERROR` — a tidier preset name is not worth the sanitizer
  job's warnings-as-errors.

- **A ccache cap is judged by `Cleanups`, not by the hit rate.** The Debug + ASan +
  UBSan job finished at **99.76% of a 256M cache having run 44 cleanups** — it was
  evicting its own objects inside a single build, while reporting a 90% hit rate
  that looked healthy. It is 1G now. The Release jobs finished at 69.7% full with
  zero cleanups and are deliberately left at 256M: the whole repository shares a
  10 GB Actions cache budget, and raising a cap that is not full spends it on
  nothing.

- **`sccache` on the Windows jobs was running, and caching into a directory that
  is deleted with the runner.** Its statistics said `Cache location  Local disk:
  "C:\Users\runneradmin\AppData\Local\Mozilla\sccache\cache"` — so nothing it
  stored ever survived the job that stored it, and the two Windows build jobs paid
  a full cold compile every run: 17.2 and 11.8 minutes of build, the second-biggest
  block in the workflow. `mozilla-actions/sccache-action` does **not** set
  `SCCACHE_GHA_ENABLED` for you — its README tells you to — and without it sccache
  never looks at the Actions cache at all. The action must also be **v0.0.11 or
  newer**: GitHub's cache service v1 is gone, and only the newer action exports the
  `ACTIONS_RESULTS_URL` / `ACTIONS_RUNTIME_TOKEN` pair the backend reads.

- **Read those statistics before `ctest`, or they are somebody else's.** The
  action's own post step reported `Compile requests 0` for both Windows build
  jobs, which reads as "the launcher was never wired in" and is not what happened:
  sccache keeps its counters **in the server**, and this suite's
  `sccache-smoke-*` tests restart that server with `SCCACHE_MEMCACHED` pointed at
  a pace-kv daemon — zeroing them, minutes before the post step reads them.

  That is the shared-cache configuration `docs/snippets/sccache-backend-caveat.md`
  exists for, and naming it here without saying so is what
  `ctest -R sccache-backend-caveat` refuses: under **MSVC** and **clang-cl**
  sccache hashes `/EP` output, which carries no paths, and replays a hit's
  `/showIncludes` with the absolute paths of the checkout that stored it, so two
  checkouts record each other's headers; `pace-cc` is the remedy, because it
  rewrites a hit's paths into the consuming checkout and refuses a hit whose
  replayed dependency is not there. Those smoke jobs compile with `g++-14`, where
  the hazard does not arise at all — which is the only reason a test in this suite
  may point sccache at a daemon.

  The
  job that does not run `ctest`, `compile-cache E2E (Windows)`, reported **231
  compile requests, 2 hits, 229 misses** from the same configuration, which is both
  the proof that the launcher works and the proof that the disk cache is cold every
  run. So the assertion that sccache handled the build runs **immediately after the
  build step and before the test step**, and a number read anywhere else in a job
  that runs the suite means nothing.

- **The Windows jobs cache now, and the cache is no longer the Windows question.**
  With `SCCACHE_GHA_ENABLED` the statistics read `ghac` rather than `Local disk`.
  Measured over 10 runs × 3 legs on 2026-09-02, every leg issues **668 or 669
  compile requests** and hits **537–663** of them, 80.4% to 99.3% — and the spread
  is *how many translation units the change touched*, not which event it was: the
  leg that missed 6 of 668 hit 99.1%, the one that missed 131 hit 80.4%, and both
  shapes occur on pull requests and on master pushes alike. What is left is not
  cacheable at all:

  <!-- table-total: none -->
  | leg | `Build`, mean | `Test`, mean | whole job, mean (min–max) |
  |---|--:|--:|--:|
  | `Windows-cl-release` | 4.7 | 3.5 | 8.5 (6.0–12.1) |
  | `Windows-clangcl-release` | 3.1 | 4.0 | 7.8 (5.6–11.3) |
  | `Windows-cl-debug` | 3.5 | 4.5 | 9.1 (6.2–14.8) |

  Roughly half of each Windows job is `ctest`, which no compiler cache touches, so
  the next Windows minute has to be bought out of the test run or not at all. The
  ticket that asked whether these jobs cache is answered; a ticket that asks how to
  make them faster is a different question with a different subject.

- **Sharing sccache entries across Windows CI runs is safe, and the reason is not
  "it seems fine".** The `/showIncludes` hazard `CompileCache.cmake` warns about
  needs an *incremental* build across checkouts at *different* absolute paths.
  Every runner builds from scratch at `D:\a\pace\pace`, so neither half
  holds. Change either — a persistent Windows runner, or a checkout somewhere else
  — and this stops being true.

- **Packaging and coverage stay on pull requests, and `package-macos` is why.** It
  is the only job that compiles with `/usr/bin/clang` and Apple's own libc++; the
  `macos` job uses Homebrew LLVM's much newer one. That is two standard libraries,
  and it is precisely the split that let `std::views::enumerate` build clean
  everywhere and break the package job. Moving it off pull requests would move that
  class of failure from the pull request to master. `package-windows` is the only
  place the MSI and the service registration are exercised at all — which is what a
  `packaging/` change breaks. Buying those minutes with a break that reaches master
  is not a trade.

  **The price was understated and one supporting clause was simply false**, and
  both are worth having straight, because a refusal has to survive being re-argued
  with correct numbers. It was re-measured on 2026-09-02 over 13 pull-request runs,
  which found the price understated (~17 claimed against 26.7 actual) and one
  supporting clause simply false ("coverage is not on the critical path"); those
  figures are superseded by the 99-run sample below and are not kept here, because
  three stacked measurements of one quantity in one bullet is how a grep finds the
  dead one first.

  Neither guard objects, so neither can be leaned on as though it were the reason.
  `check-release-gate` asserts the *list* in `release.needs`, not that each job
  runs, so a skipped job still gates. And **none of these four jobs was a required
  context** when the `default-master` ruleset was read on 2026-09-02 — neither
  `Code coverage` nor any `Package (…)` was among its contexts — so gating their
  execution would not have produced the never-arrives failure this file records
  three ways.

  Read the ruleset again before acting on that, and do **not** substitute
  `RequiredContexts` in `scripts/check-merge-queue-contexts.sh` for it. That table
  agrees today, but it is a MIRROR of a server-side setting and its own header says
  which direction it cannot see: *a context added to the ruleset and not added here
  is not caught.* Absence from the mirror is therefore not evidence of absence from
  the enforced list, and it is the enforced list that decides whether skipping a
  job strands a queued pull request. The recipe is in that header
  (`gh api …/rulesets`). The refusal is on the merits regardless, and the merits
  are `package-macos`.

  **Re-measured a third time on the 99-run sample, and the question has MOVED.**
  Dropping all four from pull requests is **102.7 → 76.6 runner-minutes (−25%)**,
  longest job 19.0 → 16.4, wall clock **24.1 → 21.4 (−11%)** — so it is still
  mostly a runner-minutes lever and barely a latency one, because `clang-tidy` is
  the longest pull-request job in 18 of 36 runs and remains so afterwards. What
  changed is where the interesting instance is: with the queue's sweep diff-scoped,
  **`Code coverage` at 14.0 min is the job most often longest in the merge queue**,
  which is on the merge path in a way the pull-request copy never was. Anyone
  reopening this should reopen it there. The `package-macos` merits are unchanged
  and still decide it.

  Read 14.0 against the 15.0 projected two sections above as *the usual winner*
  against *the mean of the maxima*, not as two answers to one question. A bimodal
  sweep is longest in the minority of entries where it escalates and is a minute in
  the rest, so the mean longest job can exceed the job that is usually longest, and
  both numbers are projections carrying the bias named there.

- **The merge queue's wall clock sits 8.2 min above its longest job, and that gap
  is runner acquisition, not the `changes` gate.** Worth knowing before anyone
  proposes ungating the queue to save it. Measured on the same sample: run creation
  to `changes` starting is **1.39 min**, but `changes` finishing to `clang-tidy`
  starting is **6.55 min** — ~20 jobs asking for hosted runners at once, across
  three events that overlap. Removing the gate buys at most the first number and
  breaks the docs-only scoping that makes a `pull_request` cost 0.6 runner-minutes.
  It follows that anything cutting the total number of concurrently queued jobs buys
  wall clock *indirectly*, and that second-order effect is **unquantified** — it is
  recorded as a direction, not as a figure.

- **`Code coverage` is four-fifths an uncached compile, and it cannot be cached.**
  Step timings over 10 code-touching pull-request runs on 2026-09-02: `Build`
  **11.05 min** (max 13.03); `Measure coverage` — the whole ~2000-case suite under
  instrumentation *plus* `llvm-profdata` and `llvm-cov` — **2.31 min** (max 2.37, a
  60 ms spread); no other step averaging over 20 seconds. So the natural guess, that only
  the report-merging step is cheap to move, is correct and useless: that step is
  already cheap. The expense is a full instrumented build with no compiler cache in
  front of it, and `cmake/Coverage.cmake` refuses to configure with one because a
  replayed object's coverage mapping names the tree it was built in. **This job
  gets shorter by running less often, never by building faster** — which puts it
  back on the `package-macos` merits above, rather than on anything a cache can do.

- **A WSL build belongs under `~`, not under `/mnt/d`, and the cost of getting it
  wrong is threefold.** `/mnt/*` is a bridge to the Windows filesystem — served
  over **9p** on WSL2, which is what `df -T` reports; DrvFs is the WSL1 mechanism
  and is what the older notes in this tree call it — and a build is almost entirely
  small-file I/O. Measured on this machine — same commit, clang 20, Debug,
  `USE_COMPILER_CACHE=OFF`, `-j8`, target `pace-kv`, a warm configure so only
  the compile is timed:

  <!-- table-total: none -->
  | | ext4 (`~`) | 9p (`/mnt/d`) | |
  |---|---|---|---|
  | build, wall | **19.6 s** | **60.5 s** | 3.1× |
  | build, user CPU | 125.2 s | 127.0 s | 1.01× |
  | build, sys CPU | 6.9 s | 19.6 s | 2.8× |
  | open+read every `*.hpp` | 0.11 s | 1.02 s | 9.3× |

  The user time is the number that settles it: the two builds did **the same
  compute**, to within 1.5%. Everything the bridge costs is spent waiting on the
  filesystem, which is also why the header walk — pure I/O, no compute — is the
  worst ratio of the four, and why the hygiene checks that read every file under
  `src/` cost an order of magnitude more there than on ext4 without anything being
  broken. This passage used to say `sccache-backend-caveat` **times out** on
  `/mnt/d`; after #502 and #479 it does not — measured 3.8–5.1 s and ~4 ms/file on
  this bridge, a few percent of its budget — and it now prints that figure on every
  run rather than leaving anyone to infer it from here.

  This is not a preference, because there is a second, harder reason: a
  **Windows-created worktree is unreadable by WSL git at all** — its `.git` file
  holds a drive-lettered path, so `scripts/local-gate.sh` dies and
  `repository-hygiene` silently skips inside one. A WSL build needs a WSL-created
  checkout, and the moment you are making one anyway, make it under `~`.

- **How you PROBE that penalty decides which number you get, by two orders of
  magnitude — so measure the syscalls, never a shell loop.** A probe that spawns
  `stat` and `rm` per iteration charges ~0.4 ms of fork and exec to *both*
  filesystems, which drags the ratio towards 1; a build issues the syscalls and
  spawns nothing per file. Same machine as the table above, WSL2 kernel
  `5.15.167.4-microsoft-standard-WSL2`, 32 cores, load average under 0.3, best of
  three, 2026-09-02:

  <!-- table-total: none -->
  | probe | ext4 (`~`) | 9p (`/mnt/d`) | ratio |
  |---|--:|--:|--:|
  | 6000 ops through a shell loop (`: >`, `stat`, `rm`) | 1.80 s | 12.02 s | 6.7× |
  | 6000 `open`+`fstat`+`unlink`, no spawns | 0.017 s (350k ops/s) | 4.12 s (1460 ops/s) | **240×** |
  | 2000 warm `stat()` | 0.0006 s (3.4M ops/s) | 1.60 s (1250 ops/s) | **~2700×** |
  | 256 MiB write + `fsync` | 0.092 s (2.8 GiB/s) | 1.14 s (224 MiB/s) | 12.4× |

  The middle two rows are what a build feels: **a warm `stat` costs about 0.3 µs on
  ext4 and about 0.8 ms on 9p**, because ext4 answers out of the dentry cache while
  9p makes a round trip to the Windows host for every one. `src/` holds **677
  entries** (648 files, 29 directories), so at 1250 stat/s a single traversal of it
  costs about **0.5 s** of bare `stat` where ext4 charges 0.2 ms — which is the
  same order as the **2.09 s** `GLOB_RECURSE` traversal independently measured in
  *The local gate* above, and why the checks that walk the tree are invisible on CI
  and on ext4 and blow their budget here. The remaining ~4× is the glob's own
  round trips per entry — `readdir`, symlink resolution, the `stat` this row times
  — and has NOT been measured, so do not read 0.5 s as a prediction of 2.09 s. A
  shell loop over the same two filesystems reports 6.7× and would justify nothing.

  Two things this does *not* say, because both were reached for while measuring it.
  A warm `ninja -n` over the whole tree runs in **0.09 s on 9p** — ninja caches and
  the page cache is warm — so anyone probing with that measures nothing and
  concludes there is no penalty. And these are probes, not a build: the build
  numbers are the table above, and a re-measurement of *those* is worth nothing
  while another lane is compiling on the same machine, which is the usual state of
  this repository.

  And a build measurement that gives each side its own `CPM_SOURCE_CACHE` makes
  both sides re-clone Catch2, zstd and lz4 — thousands of small files, which is
  precisely the access pattern the table above prices — so the configure dominates
  the thing being timed and can fail outright. That is a per-worktree cost nobody
  budgets, it is paid independently by every lane, and no per-job timing anywhere
  shows it;
  [#545](https://github.com/LASTRADA-Software/pace/issues/545) is where it is
  being dealt with. Point a measurement at the machine's populated cache instead.

  **What the shared per-machine cache buys, measured** (moved here from `AGENT.md`'s
  Building section, which points at it): Git Bash, Windows 11, cold build tree, native
  Windows volumes rather than DrvFs -- **45 s and 118 MB fetched without it, 24 s and
  1.1 MB with** -- and over DrvFs, where #545 found it, the same fetch is slow enough to
  read as a hang. *Volumes* rather than a filesystem NAME, because the two halves of this
  measurement do not share one: the cache sits under `%LOCALAPPDATA%` and the build tree
  does not, so on the machine this was taken on they are different filesystems. The
  contrast the figure exists to draw is native-against-DrvFs, and that holds either way.

## Language and ABI pitfalls

<!-- agent-tripwire: A return type is not part of a function's mangled name on Linux, so two functions differing only in return type silently collide -->

- **`readability-qualified-auto`'s own suggested fix does not COMPILE on MSVC, so
  applying it converts a Linux-only lint into a Windows-only build failure.** Over a
  `std::array`, libstdc++ and libc++ give `std::ranges::find` a **raw pointer**, so
  the check demands `auto const* const`; the MSVC STL's iterator is a **class type**,
  which that declaration cannot deduce (C3535). Writing the type out instead trips
  `modernize-use-auto`. No spelling of the declaration satisfies every toolchain.
  - **The trade is the wrong way round in both directions.** The lint is seen by
    whoever runs the sweep; the build failure lands on whoever next builds on
    Windows, which may be a different person on a different day.
  - **The tree's answer is `Core/Ranges.hpp`** -- `FindOrNull` and `FindIfOrNull`.
    Inside a template the iterator's type is dependent, so the conflict resolves
    once, there, and callers get a plain pointer with `nullptr` as the idiomatic
    *not found*. Prefer them over `std::ranges::find`/`find_if` whenever the range
    may be a `std::array` or a raw array; for `std::vector` and friends the iterator
    is a class type everywhere and either form is portable. Where a site wants a
    VALUE out of the range rather than a pointer -- a spelling, a code -- a plain
    range-based scan is also fine and names no iterator at all.
  - **`NOLINT` is not the alternative.** The rule against it is unchanged; the fix
    is to restructure so that no iterator is named.
  - **It has an entry because it kept being RE-DERIVED.** Written down in six source
    files when #1342 was filed, each discovered independently, and a census while
    closing that ticket found **17** files under `src/` carrying the explanation --
    pattern: the literal `qualified-auto`, over tracked `*.cpp` and `*.hpp`. It cost
    two lanes in one evening, both of whom diagnosed it from scratch and were right
    only because they went looking rather than applying the fix; a third would have
    applied it. It previously lived in
    [`wire-and-protocol.md`](wire-and-protocol.md), which is the wrong file for a
    toolchain fact, and had no `AGENT.md` tripwire -- so it fired in no session that
    did not already open a rules file, which is the population it was written for.

- **A read that CONSUMES its object -- `std::future::get` -- is taken into a local before a
  Catch2 assertion checks it, never inside one.** Measured with the pinned clang-tidy 22.1.8
  on Windows (steps 17-19 of the integration): `REQUIRE(stopped.get())` and
  `CHECK_FALSE(ReplyFrom(future).empty())` report `clang-analyzer-cplusplus.Move`, because
  Catch2's macros name their expression TWICE under clang (once inside
  `__builtin_constant_p`) and the MSVC STL's `std::future::get` moves `*this`. libstdc++'s
  `get` does not, so only the Windows sweep sees it -- the same one-toolchain-only shape as
  the entry above, and `NOLINT` is not the alternative here either.

- **A return type is not part of a function's name on Linux, and MSVC's mangling
  hides that.** `Core/HostPort.hpp` added an `inline Pace::ParsePort(
  std::string_view)` returning `std::optional<std::uint16_t>` while
  `Config/CliParser` already had a `Pace::ParsePort(std::string_view)`
  returning `std::expected<std::uint16_t, ConfigError>`. That is **not an
  overload**, and no compiler can say so: each translation unit sees exactly one
  of the two declarations, so both compile, and the Itanium ABI does not encode a
  return type in a free function's mangled name -- so both definitions claim the
  identical symbol, the linker keeps `CliParser`'s strong one over the header's
  weak inline, and every caller of the header version silently reaches the other.
  It reads an `expected` as an `optional`: a SIGSEGV on the first call, from code
  that is correct in isolation. Renamed to `ParseTcpPort`, with the reason at the
  declaration. Three things worth keeping:
  - **Windows cannot find this and will report the tree as green.** MSVC's
    mangling *does* include the return type, so the two are distinct symbols
    there and both link. This branch had 1730 passing MSVC tests at the moment
    Linux was segfaulting, which is the whole argument for running the Linux
    gate locally rather than discovering it in CI a phase later.
  - **A standalone reproducer will not reproduce it**, because the bug is in the
    *link*, not the code: the same calls compiled against the header alone are
    correct and pass under ASan. What identified it was `nm -C` on the library
    object, showing a strong `T Pace::ParsePort(...)` that the test binary
    had no business resolving to.
  - **The two implementations were not merged**, deliberately. The CLI's version
    distinguishes "not a number" from "out of range" because an operator needs
    to be told which; an `optional` cannot carry that. Collapsing them to share
    one body would trade a real diagnostic for a de-duplication nobody asked for
    -- the same reasoning that keeps the dispatch counters split.

- **`main` is not exempt from cognitive complexity, and the fix is extraction rather
  than a raised threshold.** The node's `main` reached 70 against clang-tidy's limit
  of 60 as the admin endpoint was wired in. Both blocks that came out --
  `AdminEndpoint::Start` and `AdoptActivatedListener` -- are coherent decisions with
  one answer each, which is why the number was a symptom worth listening to rather
  than a rule to argue with. The six bare `return 2`s it left behind became
  `ExitUsage` for the same reason: seven copies of a magic exit code is the
  table-shaped defect this list keeps recording.

- **Never run `clang-format -i` with a version other than the pinned one.** As a
  *checker* an older binary is worth something; as a *formatter* it rewrites code
  the pinned version already blessed, and the diff is invisible in review because
  every line of it is "just formatting". Running `clang-format-18 -i` on
  `FleetView.cpp` to tidy three added lines reflowed all three column tables --
  code the change never touched -- and `Check C++ style` rejected 80 lines at
  clang-format 22, none of them new.

  The repair is not to reformat again but to **restore the untouched region
  byte-for-byte** from the last commit that passed the style job, then re-insert
  only the new lines, and prove it: a diff of that region against the good commit
  must show insertions and *zero* deletions.

  So: run a non-pinned binary as `--dry-run` on the lines **you** added, never with
  `-i`, and never let it touch a file you are only passing through.

  **"The distro has no clang-format 22" is not a reason to format with 18.** The
  pinned formatter IS the PyPI build `.clang-format-version` declares, so it is one install
  away on any host with outbound HTTPS and no root -- `bash
  scripts/check-clang-format-version.sh --resolve` prints the commands when it finds
  none. Where no pip is available at all, the wheel is a zip, fetched by any host that
  has pip (add `--platform manylinux_2_27_x86_64 --only-binary=:all:` from another OS):

  ```sh
  pip download "$(bash scripts/check-clang-format-version.sh --requirement)" -d /tmp/cf --no-deps
  python3 -m zipfile -e /tmp/cf/clang_format-*.whl /tmp/cf-whl
  install -m755 /tmp/cf-whl/clang_format/data/bin/clang-format ~/.local/bin/clang-format
  ```

  With that on `PATH`, `scripts/local-gate.sh` resolves it by its banner and the whole
  tree can be formatted exactly as `Check C++ style` will judge it -- which is strictly
  better than hand-matching a style guide and then finding out in CI. Reach for the
  byte-for-byte restore above only when even this is unavailable.

  **`clang-tidy` ships the same way, and it matters more.** Successive releases add
  *checks*, so an older binary is not merely a laxer formatter -- it is silent about
  entire categories. `modernize-use-scoped-lock` and
  `readability-math-missing-parentheses` do not exist in 18, and 22's
  `bugprone-unchecked-optional-access` follows a value through a binding that 18's
  does not, so a file clean under 18 arrived at CI with thirteen findings.

  ```sh
  pip download "clang-tidy==${CLANG_TOOLS_VERSION}.1.0" -d /tmp/ct --no-deps
  python3 -m zipfile -e /tmp/ct/clang_tidy-*.whl /tmp/ct22
  ```

  **Run it in place, or through a wrapper that does.** `clang-tidy` finds its own
  resource headers *relative to the binary*, so copying just the executable out of
  the wheel produces `'stddef.h' file not found` -- and every check then reports
  against a translation unit that did not parse, which looks like a wall of real
  findings and is nothing of the kind.

  It also needs a **clang** compile database, generated with **module scanning
  off**. Pointed at a GCC one it inherits flags clang does not know; and a database
  from a module-scanning generator carries `@…modmap` arguments that do not exist
  until that target has been built, so the translation unit fails to parse and the
  file reports nothing at all. Configure it **through the preset the CI job
  configures**, into a directory of its own:

  ```sh
  cmake --preset clang-debug -B out/build/tidy22 -DENABLE_TIDY=OFF \
        -DCMAKE_CXX_SCAN_FOR_MODULES=OFF -DPACE_ENABLE_TLS=ON \
        -DPACE_BUILD_BENCHMARKS=ON -DPACE_BUILD_TESTCLIENT=ON
  ```

  **Not a hand-rolled `cmake -S . -B …` equivalent**, which is what stood here and
  what `tidy-sweep.sh` documented until #454. A bare configure line inherits
  `PEDANTIC_COMPILER` and `PEDANTIC_COMPILER_WERROR` OFF, so its database carries
  neither `-Wall -Wextra -Wconversion -pedantic` nor the `-Wno-…` suppressions that
  accompany them — **29 flags apart on the same translation unit**. `.clang-tidy`
  enables `clang-diagnostic-*`, so those flags decide what the sweep reports, and it
  diverges *in both directions at once*: findings CI suppresses appear, and findings
  CI raises do not. Measured: a `double`→`int` return that CI's database reports as
  `clang-diagnostic-float-conversion` produced **nothing** from the hand-rolled one.
  The noisy direction wastes a cycle; the blind direction ships to CI, and both read
  like a clean tree.

  That is one of #454's two halves. The other is below, under
  "`PEDANTIC_COMPILER_WERROR` decides fatality, not which warnings exist": the
  three `clang-diagnostic-c2y-extensions` findings it reported are what a database
  with `PEDANTIC_COMPILER` **ON** and `WERROR` **OFF** produces, which is what a
  build directory reused across presets holds — and which no correction to the
  configure line could have explained. A symptom with two mechanisms reads as
  unreproducible the moment either one alone is ruled out.

  It is also how the target-set bullet above gets violated by the very page that
  states it: the old line omitted the two default-OFF app targets, so four
  first-party translation units were absent from the database rather than clean.
  A rule whose own example contradicts it is worse than no example.

  `-B` overrides the preset's `binaryDir`, which is what keeps this out of the
  `out/build/clang-debug` tree a DEVELOPER builds in — configuring the sweep's
  database must not turn `ENABLE_TIDY` and module scanning off in that one. (It
  used to be the tree `local-gate.sh` built in as well; since
  [#487](https://github.com/LASTRADA-Software/pace/issues/487) the gate owns
  `out/build/gate-*` and reaches this one no more than the sweep does. The
  reasoning is unchanged — only the list of things that would otherwise collide in
  there got shorter.)

  The line is the `clang-tidy` job's `Configure` step verbatim plus `-B`, and
  `ctest -R tidy-sweep-database` asserts it stays that way: nothing else connects
  the workflow to the two places that document it.

  Verbatim duplication is right *under the constraint it was written under* and
  wrong permanently — [#615](https://github.com/LASTRADA-Software/pace/issues/615)
  carries the `tidy22` preset that removes it, and must be taken by whoever can
  change `build.yml` in the same change: a preset CI does not adopt is a fourth
  copy, not a consolidation. The check moves to comparing against the preset in
  that same change, or it fails correctly and confusingly against documentation
  that is still right.

- **A sweep that cannot prove the tool ran is worth nothing, and reads like
  success.** Every way of getting clang-tidy wrong above -- an unset execute bit
  (the wheel does not carry one), a wrapper that cannot exec, a missing resource
  dir, an unparseable `@modmap` -- produces *silence*, and silence filtered through
  `grep 'error:'` is indistinguishable from a clean file. This branch shipped to CI
  twice on sweeps that had reported clean while executing nothing.

  `scripts/tidy-sweep.sh` is that lesson in executable form: it canaries the binary
  against a real source file first, treats exit codes ≥ 126 as fatal rather than as
  findings, and refuses to print a clean verdict it did not earn. Use it, and if you
  write a one-off loop instead, make it fail loudly the same way.

  **The exit status and the output are read TOGETHER, per unit.** A non-zero exit is
  how clang-tidy reports findings AND how it reports a unit it did not process, and
  the second can come with no diagnostic line at all. The sweep used to read only
  `rc ≥ 126` as a failure and filter everything else through `grep 'error:|warning:'`,
  so a unit exiting 1 in silence was summed into `CLEAN` -- measured end to end with a
  stub that did exactly that on all 698 units: `TIDY SWEEP CLEAN (502 of 504
  file(s) contributed code …)`, exit 0. `TidyUnitVerdict` now answers `unanalysed`
  for it, and the table fails CLOSED: `clean` needs a zero exit, or a non-zero one
  whose only DIAGNOSTIC lines are unknown-warning-option ones -- non-diagnostic lines
  (`Error while processing`, `Stack dump:`) are tolerated there, because a crash exits
  at or above 126 and is `fatal` first -- measured under Git Bash for a RELEASE-CRT
  program: an access violation 139, a stack overflow, `__fastfail` and `abort()` 127. A
  Debug-CRT `abort()` exits 3 (measured), and the pinned 22.1.8 `clang-tidy.exe` is a
  release-CRT build by its import table (`VCRUNTIME140`, `MSVCP140`, `api-ms-win-crt-*`;
  no `ucrtbased`, `vcruntime140d` or `msvcp140d`); a Debug-CRT crash with no diagnostic
  line would land on `unanalysed`, still a failure -- and "no checks enabled" is the canary's
  question. Those lines are judged by their TAG at the end of the line, never by the
  words: a substring filter swallowed a finding that mentioned them. The build's
  own path, `CMAKE_CXX_CLANG_TIDY` (what `local-gate.sh`'s clang-debug leg runs),
  already fails: CMake's co-compile step returns clang-tidy's status and builds no
  object, measured against the same stub.

  **A tool that parses is not a tool that reports on HEADERS.** A header finding is
  kept only when `HeaderFilterRegex` takes the header's path *as clang spells it on
  that host*, and clang joins an include directory to a header name with the host's
  separator: a cl or clang-cl database reports `D:\...\src\tests\X.hpp`, or
  `D:\...\src\Pace/Core/X.hpp` where `-I...\src` meets a `/` include. The
  pattern wrote every separator as `/`, so the `clang-tidy-windows` leg discarded
  every first-party header finding as non-user code and reported clean -- measured
  with the pinned 22.1.8, native, over both Windows databases, by a planted `g_`
  global in `src/tests/WindowsErrorPopups.hpp` that exited 0 before and 1 after.
  The unit canary could not see it: the unit parsed. So the gate's coverage count
  asks every header in the three spellings clang produces, generated on every host,
  and `tidy-sweep.sh`'s `HeaderCanary` plants a finding in a sibling-included and an
  `-I`-included header and stops unless the analyser reports both. On Windows by
  hand, pass nothing: the repository's pattern is the one to test. Run from INSIDE the
  build directory of a database that scans modules, since its `@*.modmap` response
  files are relative.

  "Refuses a verdict it did not earn" is four separate refusals, and each one closes
  a path that ends in `CLEAN` over nothing: the plan's exit status is *observed*
  (`mapfile < <(plan)` throws it away, and every way a compile database can fail to
  parse then yields zero rows, which reads as "nothing to sweep"); the include scan
  is fatal when `grep` **fails** rather than merely matching nothing (an empty graph
  silently narrows the scope to the changed `.cpp` files); a plan with units in it
  and none of them present in the tree is fatal, not `CLEAN (0 translation
  unit(s))`; and the extension table that decides what may be handed to clang-tidy
  is a table, so a `.c` unit cannot be walked into the graph and dropped on the way
  out. The self-test also pins `LC_ALL=C` on its ordering — under `en_US.UTF-8`
  `sort` collates case-insensitively and the assertions fail on a developer's
  machine while passing on a runner's `C.UTF-8`.

  And the sharper form of the same failure, because the canary above does **not**
  catch it: **the tool can run, exit 0, and have analysed nothing.** Every guard in
  this paragraph asks whether clang-tidy *executed*; none asks whether it had any
  check enabled while it did. `--checks=-*,clang-diagnostic-c2y-extensions` selects
  no check at all in clang-tidy 22 — `clang-diagnostic-*` is a **filter over compiler
  diagnostics, not a check that can be enabled by a glob** — so a sweep spelled that
  way reports `0 findings` for every translation unit, with a successful exit status,
  a proven-executable binary and a database that parses. Measured while investigating
  #454: six full sweeps across four compile databases, all reading zero, all
  worthless. The only thing that exposed it was a deliberately planted finding that
  *also* read zero. So a `--checks` expression narrowed for speed is itself an
  instrument, and it is calibrated the way every other instrument here is — plant a
  finding the expression must report, and watch it report it, before believing a run
  of zeroes. `Error: no checks enabled` on stderr is the tell, and `--quiet` plus a
  `grep` hides it.

- **A `bool` in the middle of a config struct costs seven bytes, and four of them
  fail the build.** `clang-analyzer-optin.performance.Padding` permits 24 bytes more
  padding than an optimal field order would give, and `NodeConfig` is almost entirely
  `std::string` and `std::filesystem::path` -- so a one-byte member between two of
  those is padded out to a full eight rather than costing one. Adding `--dashboard`
  and `--tls-self-signed` beside the settings they configure took the struct to 38
  bytes against an optimal 6, and the `clang-tidy` job -- the only one that runs the
  analyzer -- rejected it.

  Keep every `bool` and byte-wide enum in **one run**, which that struct already half
  did with its trailing flags. Two of the four moved were pre-existing (`logLevel`,
  `serviceScope`), and that was the point: moving only the two new ones lands on
  *exactly* 24, which passes and leaves the next contributor's `bool` to break it
  again. Moving all four lands on 8. A field's position there is a layout constraint,
  not where it reads most naturally, so the run says so in a comment.

  The check is `BaselinePad - OptimalPad > 24` and both terms are arithmetic over
  `sizeof`, so it reproduces **without the analyzer**: sum the field sizes, subtract
  from `sizeof(T)`, and compare against the same sum laid out by descending
  alignment. Worth knowing because it gives an exact number where re-running CI gives
  a yes or no -- and because a host without the pinned clang-tidy can still check it.

- **A `static_assert` that anchors a table's length on an enumerator BY NAME is a
  guard that fires only when nothing is wrong.** Casting an enumerator to an index
  is safe exactly while the table holds one row per enumerator in enumerator order,
  and this tree used to spell that rule five ways across eight tables -- of which
  **six failed open in the one situation the rule exists for**. Four were anchored
  by name:

  ```cpp
  static_assert(Table.size() == static_cast<std::size_t>(Enum::TheLastOneToday) + 1);
  ```

  Append an enumerator and *forget* the row: `size()` still equals
  `TheLastOneToday + 1`, so it compiles, and the lookup then reads past the end --
  reproduced verbatim under ASan as a `global-buffer-overflow` four bytes past
  `RefusalTable`. Append one and *remember* the row: the size is now one greater
  and the assert fails. It is inverted, and nothing about reading it says so. Two
  more tables had no length tie at all, and one of those, `Consensus::RoleTable`,
  was reached by a linear scan that fell back to `RoleTable.front()` -- so a
  missing row returned a **follower's** traits for a leader, silently, which is
  worse than the crash. `Core/EnumTable.hpp` is the one spelling now: `Last`
  states the enum's own count, `EnumTable<Enum, Row>` takes its extent from that
  so a short table cannot be *declared*, and `RowsInEnumeratorOrder(table,
  &Row::member)` checks the extent and every row's position in one assert.
  Consequences that are each load-bearing:
  - **The row carries the enumerator it describes, and that is what makes the
    order checkable at all.** A bare array of values can only have its length
    asserted -- which is why the three bare ones (`RoleNames`,
    `ProposalRefusals`, `PickErrorTable`) recorded their order in trailing
    comments no compiler reads. Giving them struct rows is not decoration; it is
    the difference between a checked invariant and a documented hope.
  - **`Last` is a cost to measure, not to assume.** It was free for these six
    because nothing in the tree switches over any of them -- grepped, not
    guessed. Adding a sentinel to an enum whose callers deliberately omit
    `default:` turns every one of those `switch`es into a build error, and this
    codebase omits `default:` on purpose in several places (`PathCanon::Anchor`,
    `DirectManifest::PathRole`) precisely so a new state is a compile error. That
    trade has to be made rather than inherited.
  - **A proved order turns the lookup into an index rather than a search.**
    `TraitsOf` scanned `RoleTable` and carried an eight-line comment re-deriving
    the `std::array`-iterator portability argument that `Core/Ranges.hpp` already
    documents; with the position guaranteed there is nothing to search for, and
    the comment went with the scan.
  - **The guard was verified by reintroducing the defect at all six sites.** One
    throwaway enumerator appended with no row, and each of the six now fails to
    compile naming its own table. A completeness guard that has never been seen
    to fail is exactly the thing this entry is about.

- **An instruction-set extension is used only inside a function that asks for it, never enabled by
  a global `-m` flag.** That is `__attribute__((target("sha,ssse3,sse4.1")))` on gcc and clang
  (clang-cl included), and nothing on MSVC's cl, which allows the intrinsics anywhere and does not
  know the attribute. The attribute alone does not make the call safe: an attributed function runs
  only once `Core/CpuFeatures` has said the CPU has its instructions (#1420). Every CI runner has
  the instructions, so a violation passes there and dies only on a CPU without them, which is why
  the rule is asked of the FLAGS rather than of a run: `ctest -R instruction-set-flags` reads each
  test leg's compile database and plants a flag it must refuse, each Package job asks the build that
  ships through `scripts/check-instruction-set-flags.sh`, and `ctest -R target-pragmas` refuses a
  target pragma under `src/` (#1442). What neither covers is listed in the checks' headers.
  - **And a database records only what CMake PUT on a command line** (#1447). The build-time
    environment (`CL`, `_CL_`, `CCC_OVERRIDE_OPTIONS`), a clang driver configuration file and a
    compiler's built-in default all widen the instruction set without appearing there. They all
    arrive in the compiler's PREDEFINED MACROS, so every executable compiles
    `src/tests/InstructionSetBaseline.cpp` (`cmake/InstructionSetProbe.cmake`), which `#error`s
    naming each macro above its architecture's baseline row. It is a unit the BUILD compiles
    rather than a check a test runs, because a test inherits ctest's environment, which need not be
    the build's: a `CL` set for the build and not for the suite passes any probe driven from ctest.
    **An architecture with no row is refused, not passed.** The two complement each other -- #1442
    names the FLAG, the probe names the MACRO -- and `ctest -R instruction-set-probe-selftest`
    drives the refusing direction with this build's own compiler (every leg's build is the passing
    one): a flag, `CL=/arch:AVX2` for cl, `CCC_OVERRIDE_OPTIONS` and `--config` for clang, and a
    target-attributed function that must pass. cl's `#error` is FATAL, so it names the FIRST row
    it reaches -- `__AVX__` for `/arch:AVX2` -- where clang names every one.
  - **And nothing made a FUTURE shipping configure get that step** (#1450). #1442 put it into the
    three `Package` jobs, and that step is the only thing reading what SHIPS -- the macOS package is
    configured by a hand-written `cmake` line no `ctest` leg configures. A fourth packaging job, a
    new configure line in an existing one, or the step reordered below the build would ship
    unchecked, and **every required context would stay green, because `Package` jobs are not
    required contexts.** `ctest -R shipping-configure-guard` selects on the
    `-DPACE_BUILD_TESTS=OFF` FLAG rather than on three job names, so a fourth job is something
    it FINDS; it matches the guard on that configure's own build directory, not merely on the job,
    because a copied step naming another configure's database is the likeliest wrong shape and a
    per-job existence test cannot see it. Four verdicts rather than one flag -- same job, before the
    build, no `if:`, no `continue-on-error:` -- because a condition is how a step REPORTS without
    gating and `continue-on-error` is how it GATES without failing, and a refusal naming the wrong
    one sends somebody to delete the wrong line. `Dockerfile` carries a shipping configure and is
    exempt BY ROW with its reason (the image reaches no registry, and `docker build`'s filesystem
    holds no database the job can read); a row matching nothing is refused as stale. **Zero shipping
    configures is a REFUSAL**, because every verdict here is about something missing.
  - **A global flag is wrong even when it is set on one file.** A translation unit built with
    `-msha -msse4.1` emits its own out-of-line copies of every inline function it uses:
    `std::span::subspan`, the `views::iota` iterator, and so on. The linker keeps one arbitrary
    copy for the whole program -- the ODR shape of `PACE_RANGES_FORCE_FALLBACK`'s per-TU define
    above. The scalar fallback, running on a CPU without those instructions, can then execute
    the copy that has them and die of SIGILL. The attribute keeps the instructions inside the
    attributed bodies. It also needs no per-source flag in each target that compiles the file,
    and `Core/Sha256.cpp` is compiled by two (the library and the launcher).
  - **The attribute is not inherited by what the function contains.** A lambda inside an
    attributed function is a separate function, so gcc refuses to inline an intrinsic into it.
    A helper is its own attributed function.
  - **gcc refuses `std::array<__m128i, N>`** ("ignoring attributes on template argument"),
    because the vector type carries attributes. A sliding window of named vectors is the
    portable spelling.
  - **A default target that enables an extension is not a reason to omit the attribute.** Every
    Apple arm64 CPU has the SHA-256 instructions and the default target enables them, but a build
    given an explicit `-march=armv8-a` refuses to inline `vsha256hq_u32` into a function that did
    not ask. Measured with clang 20: "always_inline function 'vsha256hq_u32' requires target
    feature 'sha2'".
  - **A hardware path exists only where a CI leg compiles and runs it**, which is the `Ranges`
    fallback rule above applied to an engine: a branch no leg compiles rots with nothing to
    report it. The platforms still on the scalar path are under Open work (#1432).

- **MSVC 19.44 targeting ARM64 miscompiled two coroutine shapes, and each is fixed at its one
  site rather than guarded tree-wide.** Measured with cl 19.44.35228, `cl-release`, on the
  `windows-11-arm` runner, and on nothing else: the same cases pass on the x64 MSVC, clang-cl,
  gcc and clang legs AND on gcc for Linux ARM64, so this is a fact about that compiler for that
  target, not about "MSVC" and not about "ARM64". Debug was not measured either way.
  - **A call's result held across a `co_await` was kept on the resume function's STACK** (#1545).
    `HandleMs` parsed its flags before the two payload reads and used them after. The ARM64
    `/FAs` listing shows `ParseSetFlags` returning through `x8` into the stack area (`x23+0x110`,
    `x23` being sp after `sub sp,sp,#0x4D0`), and every flag read after resuming loading from
    there -- the stack of a LATER activation -- while the key and the saved source tag beside it
    came from the coroutine frame. A CAS-guarded append ran as a quiet store and answered nothing.
    **So compute such a value after the last `co_await` it would otherwise have to survive, or
    re-derive it there**: `MemcachedMeta.cpp`'s `HandleMs` now parses after the reads. A synthetic
    copy of the function's shape was copied into the frame correctly, so the trigger is NOT known
    and the shape cannot be recognised by reading source -- which is why the remedy is structural.
  - **A `co_await` on a TEMPORARY awaiter whose `await_ready` made a virtual call lost its enclosing
    `try` block** (#1546). `DelayAwaiter::await_ready` read the clock through `IClock::now()`, and the
    `OperationCancelled` its `await_resume` threw passed a typed `catch` and `catch (...)` alike.
    Measured: it escapes for that shape, also with `await_suspend` `noexcept` and with the stop
    callback member moved; it is caught when `await_ready` makes no call, when the clock is read in
    the constructor, and when the same awaiter is a named local. The listing shows what went
    missing. The resume function's exception table declares ONE try block, the coroutine's own
    catch-all. The typed handler is emitted, but no try-map entry names it. With the fix the table
    declares two. **So an `await_ready` stays
    trivial -- a member read or a constant -- and a decision that needs a call moves into
    `await_suspend`**, which may decline to park. The vendored
    `vendor/endo/tui/runtime/TuiRuntime.hpp`'s `DelayAwaiter` answered a constant `false` (endo
    `c09959fc`) until #1596 moved that code to core-cpp, whose v0.1.0 `EventLoop::DelayAwaiter`
    reads the clock in `await_ready` again -- reported upstream, since every delay here goes
    through it now.
  - **The evidence, by run**: 35340951724 is the failure; 35346860955 and 35348183117 the
    #1546 variants, on master and on #1432's branch; 35350059398 the #1545 flags read back as
    garbage beside an intact tag; 35352105607 the listing; 35354435799 both fixes built as CI
    builds, with a control leg on which the new #1545 case fails three runs out of three;
    35366019632 the #1546 exception tables, with and without the fix.
  - **What guards it is small, and is stated as such.** Two pins: "meta ms keeps its flags across
    the payload read" dirties the stack under the reads and fails only where the compiler misplaces
    the flags, and `TuiRuntime_test.cpp` `static_assert`s that `await_ready` is a constant, so
    reading the clock there fails to COMPILE everywhere. Neither can fail on x64 or under a
    sanitizer, because the C++ is correct. The NEXT instance of either shape is seen only by the
    ctest of the `Windows-cl-release-arm64` leg #1432 adds, which is `NotBinding` in
    `check-merge-queue-contexts.sh`: its failure stops no merge, and `merge-group-report.yml`
    reports it.
  - **The stack-slot audit is a probe, not a CI check, by decision.**
    `scripts/probes/msvc-arm64-coro-stack-slots.py` reads `/FAs` listings, builds each resume
    function's control flow (jump tables included), and names every read of a slot a call's
    result was returned into through `x8` that a path of the SAME activation reaches unwritten.
    It is kept as a probe because what it yields is candidates, not proof -- a value spilled to
    the stack any other way is not looked for at all -- it needs an ARM64 build with listings, and
    a heuristic check that fails on arrival gets disabled. Measured with it on run 35362081853,
    over the 307 production translation units (the library, `pace-kv`, `pace-cc`,
    `pacectl`, `pace-node` and the vendored tui): all 303 resume functions
    modelled, and master's `HandleMs` the only one with candidates -- 21 reads of its flags --
    and none with the fix. **Its first version read the listing in text order and passed every
    small-frame resume function without reading it**, so the clean result first reported for 307
    units covered only part of them; a function it cannot model is now named, never passed.

## What a `char` is

<!-- agent-tripwire: A `char` is UTF-8 here, at run time and at compile time -->

- **Every Windows executable declares UTF-8 as its process code page, and the
  declaration is applied by walking the build system rather than by a line per
  target.** Windows keeps command lines, environment blocks and paths as UTF-16 and
  transcodes them for a narrow caller through the process's *active code page*,
  whose default is the host's legacy one — 1252 on a Western install. That one
  setting decides `argv`, `getenv`, every `...A` API this tree calls
  (`CreateProcessA` in the launcher's process runner, `CreateServiceA` and
  `GetModuleFileNameA` in `ServiceControl`, `RegQueryValueExA` in `Registry`) and
  `std::filesystem::path`'s narrow conversions in BOTH directions — MSVC's
  `__std_fs_code_page()` answers `CP_ACP` unless the CRT locale is UTF-8. Since #141
  the fleet refuses a registration whose fields are not valid UTF-8, so a non-ASCII
  `--toolchain` or `--advertise` typed on a Windows console was refused for a reason
  invisible from where it was typed (#155).

  **The obvious fix is the wrong one.** `GetCommandLineW` + `CommandLineToArgvW` +
  `WideCharToMultiByte` in a seam every `main` calls converts ONE boundary and
  leaves the rest on the legacy page — which turns a wrong encoding into a *split*
  one: UTF-8 `argv` handed to `std::filesystem::path` decodes as CP-1252 and names a
  different file, and handed to `CreateProcessA` spawns the compiler with a mangled
  command line. Both work today. Closing that gap means policing a second convention
  across 45 path constructions, 122 `.string()` calls and six `...A` call sites,
  forever, with no compiler enforcement. `cmake/Utf8CodePage.cmake` carries the
  measurements.

- **`activeCodePage` is honoured from Windows 10 1903 / Server 2022 and ignored in
  silence below it**, which is the one thing a build-time setting must not be
  allowed to be. `Pace::NarrowTextIsUtf8()` reports the OUTCOME rather than the
  intent, a Catch2 case asserts it — red at code page 1252, green at 65001 — and the
  node names the active code page in a parse refusal when it is not UTF-8, which on
  such a host is the whole answer and no other surface would ever give it.

- **`utf8-argv-*` is the only end-to-end proof there can be.** The defect is in what
  the OS hands a process, so nothing *inside* a process can observe it: a Catch2 case
  can assert the code page a test binary ended up with, and only running a real
  executable says what an argument BECAME on the way in. Each binary with an option
  table is run with an unrecognised flag spelled with U+00FC and must echo those
  exact bytes; the argument is built with `string(ASCII 103 114 195 188 110 …)`, raw
  byte values, so no file's own encoding is what is under test.

- **`std::filesystem::path`'s narrow constructor THROWS once the active code page is
  UTF-8** and the bytes are not — `MultiByteToWideChar(CP_UTF8, MB_ERR_INVALID_CHARS,
  …)` refuses them — and it throws *before* any `std::error_code` overload downstream
  is reached, so a call site that carefully takes an `error_code` for every operation
  is still not protected. `Platform::PathFromNarrowText` is the one `catch` in this
  project's own code, and one rather than none because the standard library states
  this failure by throwing and offers no `error_code` overload of the constructor to
  ask instead. It is a guard, not a decision: where readability *decides* something,
  the caller asks `Utf8FromNarrowText` and says what it does about the answer.

- **A CHILD process has a code page of its own, and `cl.exe` does not use even that
  for output.** It writes the paths in `/showIncludes` in the CONSOLE OUTPUT code
  page — measured on this tree's toolchain at `C3 BC` for U+00FC under CP 65001 and
  `81` under CP 850. See `.agent/rules/compile-cache.md` for what the launcher does
  about it.

- **`/utf-8` is on for MSVC, so the compiler agrees with the runtime about what a
  narrow literal is.** Without it MSVC reads a source file in the host's ANSI code
  page and re-encodes its narrow literals into that same page: byte-identical on a
  CP-1252 or CP-65001 host, different bytes anywhere else. This tree has such
  literals (a Redis error reply, the Windows service description, an SVG chart
  caption), and the SVG one is the sharp end — an XML parser refuses a whole
  document whose encoding does not hold. Directory-scoped and applied after every
  CPM dependency has been added, exactly as `PedanticCompiler` and `Sanitizers` are,
  so a third-party source carrying a byte it would refuse never sees the flag.

## Line endings

<!-- agent-tripwire: Line endings are LF everywhere, enforced by `.gitattributes` -->

Line endings are LF everywhere, and that is a `.gitattributes` rule
(`* text=auto eol=lf`) rather than an instruction to set `core.autocrlf`. The
config is per-clone and per-developer, so without the rule two people editing one
file disagree about what a line ending is — and the disagreement is invisible
until a diff comes back as *every line changed* for a two-line edit, which is how
it was found. Stored content was already LF, so the rule changed nothing that is
committed, only what lands on disk at checkout. `*.sh` keeps a row of its own even
though the general rule covers it, because the consequence there is specific: a
CRLF shebang makes the kernel look for an interpreter whose name ends in a
carriage return, so such a script does not misbehave — it fails to start at all.
## A reference build that is not one is wrong in BOTH directions

<!-- agent-tripwire: A reference-build refusal is a REFUSAL and not a warning -->

- **The gate REFUSES a launcher-fronted build rather than warning about it, and the
  reason is the direction nobody investigates.** The observed case
  ([#626](https://github.com/LASTRADA-Software/pace/issues/626)) was five
  metrics counter tests failing in four files the branch never touched, on a
  launcher-fronted MSVC build, all clearing with `-DUSE_COMPILER_CACHE=OFF` — a
  false alarm, which costs somebody an investigation. **The same substituted object
  can equally HIDE a real failure, and nothing would say so.** A verdict about a
  tree that was not built cannot be read in either direction, so there is no safe
  way to continue past it — which is what makes it a refusal. That sentence lives
  in the refusal's own text, because a developer who meets it should learn why it
  is not a warning.

- **The guard was already there and the ticket did not know.** `launcher_verdict`
  in `scripts/local-gate.sh` reads `build.ninja`, refuses rather than warns, states
  its count, and separates `unknown` and `unreadable` from `0` — all of it landed
  under #319/#368, citing neither #626 nor #454. Check a ticket's premise against
  the tree before building to it; a body describing a solved half is #779's shape.

- **The count is LAUNCHER BINDINGS, not edges, and it was called edges.** Ninja
  emits one `LAUNCHER = ` line per RULE where the value is uniform, so this tree on
  Linux reads **5, covering 501 compile edges**, while #626's Windows reproduction
  recorded **669**. Those are not comparable and nothing said so. The verdict is
  unaffected — any count above zero refuses — but a refusal message is read by
  somebody holding another platform's number, which is the whole reason it exists.
  **A unit error in a refusal message is how two numbers get compared that should
  not be.**

- **And the guard is blind to a compiler that IS a cache.** Measured on
  `gate-clang-debug`, the gate's own preset with the gate's own pin: `launcher_verdict`
  answers **0** — correctly, there is no `LAUNCHER` binding — while
  `CMAKE_CXX_COMPILER` resolves to `/usr/lib64/ccache/clang++`, because the preset
  spells a bare `clang++` and `/usr/lib64/ccache` precedes `/usr/bin` on that host's
  `PATH`. The blind spot is **total**, not partial, and it is
  [#804](https://github.com/LASTRADA-Software/pace/issues/804).

- On Linux the #626 symptom **does not reproduce** in either cache state: three full
  builds of one tree — populated shared caches, cold caches, and a reference build —
  and three full suites, with all five metrics tests passing in every arm. Stated as
  an analogue: #626's reproduction is Windows/MSVC/sccache and was not executed.
  **And the populated arm is weaker than it looks** — the cold build recorded exactly
  131 ccache hits, which is exactly the number of duplicate compilations in the tree,
  so every hit was intra-build and the populated one replayed only a handful more.
  A cache keyed per build directory is [#816](https://github.com/LASTRADA-Software/pace/issues/816).

## `PEDANTIC_COMPILER_WERROR` decides fatality, not which warnings exist

<!-- agent-tripwire: `PEDANTIC_COMPILER_WERROR` decides **fatality, not which warnings exist** -->

- **A flag and the suppressions it makes necessary are governed by ONE condition.**
  `cmake/portable/PedanticCompiler.cmake` added `-pedantic` and
  `-Wmissing-declarations` under `PEDANTIC_COMPILER`, and the suppressions those
  make necessary — `-Wno-c2y-extensions`, `-Wno-c++20-extensions`,
  `-Wno-missing-declarations`, `-Wno-class-memaccess` — inside the
  `PEDANTIC_COMPILER_WERROR` block. Two conditions over one concern, so **the four
  presets that inherit `PEDANTIC_COMPILER=ON` from `base` and leave `WERROR` off
  got the warnings and none of the suppressions**: `clang-coverage`,
  `clang-asan-ubsan`, `clang-tsan`, `clang-tracy`
  ([#611](https://github.com/LASTRADA-Software/pace/issues/611)).

  Measured on `0db96dc8`, each preset in its OWN fresh build directory against
  `/usr/bin/clang++` pinned by absolute path with zero `LAUNCHER =` edges: **7049
  `-Wc2y-extensions` warnings across 195 translation units, the same number in all
  four**, every one of them `'__COUNTER__' is a C2y extension` out of Catch2's
  `TEST_CASE` — so the count is a function of how many tests exist. The other three
  suppressions cover diagnostics that fire **zero** times on this tree at clang
  22.1.8: three suppress nothing and one suppresses everything, which is why
  nobody's intuition about which flag mattered would have been right.

  **Nothing could have reported it, in any direction somebody would look.** Those
  four presets have `WERROR` off, so 7049 warnings are 7049 warnings and every
  build exits 0. The preset people actually run — `clang-debug` — has `WERROR` on
  and is therefore correct. And the one place it becomes *visible* is a clang-tidy
  database from a build directory configured that way, where it reads as a stale
  cache rather than as a rule. That is exactly how
  [#454](https://github.com/LASTRADA-Software/pace/issues/454) came to be
  filed and then believed unreproducible: its three `clang-diagnostic-c2y-extensions`
  findings are this, and `-Wc2y-extensions` being pedantic-only in clang 22 made the
  hand-rolled configure line look like the whole story when it was half of it.

- **Split by what a flag DOES, never by where it happened to live.** `-Wno-X`
  selects a *diagnostic* and belongs beside the flag that makes it necessary;
  `-Werror` and `-Wno-error=X` decide *fatality* and belong under `WERROR`.
  `-Wno-error=X` says "keep X visible, do not fail on it", so a preset without
  `-Werror` that SEES X is getting precisely what that flag asks for — it is not
  this defect, and a rule that refused it would be turned off rather than obeyed.

- **Copying a suppression outward while leaving it inward does not close this.**
  Two conditions naming one diagnostic *is* the defect; the second copy is a second
  thing to keep in step. Move the flag.

- The `-Wno-error=` half is **belt-and-braces WHERE IT IS PAIRED, not dead code by
  proof**. A diagnostic disabled by `-Wno-X` can never be an error, so a paired
  `-Wno-error=X` matters only on a compiler where the `-Wno-X` probe fails while its
  own succeeds. Measured on clang 22.1.8 and GCC 16.2.1, the two halves of every
  PAIR succeed and fail **together** — clang rejects both spellings of
  `class-memaccess`, GCC rejects both of `c2y-extensions` — so those four are
  currently inert. That is a property of two compilers, not of the flags, which is
  why they stay.
  - **An UNPAIRED `-Wno-error=X` is the opposite: load-bearing by construction**, and
    reading the paragraph above as covering the whole family is how it goes stale.
    `-Wno-error=array-bounds` and `-Wno-error=maybe-uninitialized` have no `-Wno-`
    half and are what lets GCC 16.2.1 build this tree at all
    ([#805](https://github.com/LASTRADA-Software/pace/issues/805)): both fire
    inside libstdc++'s headers, from inlining, on code with no defect to fix, and
    g++-13/g++-14 report neither. They are gated to `GNU` — only GCC produces them,
    and ungated they would cost clang `-Werror` on two diagnostics that name real
    bugs. Deleting one as belt-and-braces takes `gate-gcc-release` red on every
    branch at once, which is the state #805 exists to have ended.
  - Retiring them is a MEASUREMENT, never a guess: a later GCC fixing the false
    positive is what makes them inert, and the check is that the tree still builds
    with the row removed. Three source rewrites of `EncodeCompileValue` were each
    measured to silence one compiler and break another — one of them shipped
    (166880b6) and took `Linux-gcc-release` red — so **the source is not the place**,
    and a fourth attempt needs a GCC 16 AND a g++-13/14 before it lands.

- **Fatality is spelled per FRONTEND: `-Werror` on a GNU-style driver, `/WX` on an
  MSVC-style one, `clang-cl` included** (it has clang's ID and MSVC's frontend, so it
  takes `/W4` and therefore `/WX`). The MSVC `/WX` sat commented out from the first
  commit, so no Windows preset was ever fatal, while AGENT.md said warnings break the
  Windows build. Master's four Windows CI legs were green over fourteen first-party
  warning sites, and the fatality table asserted the absence as correct.
  - On MSVC a warning `/W4` makes visible is fixed at the source. One that reports
    INTENDED behaviour, with no source change that keeps the behaviour, is a
    `<flag>|<rationale>` row of `PEDANTIC_COMPILER_MSVC_SUPPRESSIONS` in
    `cmake/PedanticSuppressions.cmake`, applied beside `/W4` — a statement about which
    warnings exist, so `PEDANTIC_COMPILER`'s. It is never a `#pragma` at the site and
    never a fatality exemption. C4324 is such a row: `alignas` padding
    `InMemoryLruStorage`'s cache-line layout, and every struct holding one.

- **`ctest -R pedantic-suppressions` is the reader, and it DRIVES the file rather
  than scanning it.** It includes `PedanticCompiler.cmake` twice per compiler
  persona — the pair `CMAKE_CXX_COMPILER_ID`/`CMAKE_CXX_COMPILER_FRONTEND_VARIANT`,
  because `clang-cl` has clang's ID and MSVC's frontend and takes the other branch —
  with `add_compile_options` replaced by a recorder and `check_cxx_compiler_flag`
  stubbed through `CMAKE_MODULE_PATH`, and refuses any difference between the two
  `WERROR` settings that is not fatality-only. A text scan would have to model
  `if`/`elseif`/`else`/`endif` nesting to answer *which condition is this line
  under*, which is the one question that matters here, and a model of CMake that is
  subtly wrong fails in the confident direction. Including the file uses CMake's own
  answer. The stub answers **yes to every probe** deliberately: a probe that failed
  would drop a flag for a reason unrelated to the rule, and a dropped flag cannot
  violate it — so a real compiler would weaken the check on exactly the hosts where
  a flag is unavailable, invisibly.

- A guard nobody has watched refuse is not a guard, and *"it was seen failing before
  the fix"* is a fact about one commit that stops reproducing the moment the fix
  lands. `ctest -R pedantic-suppressions-selftest` runs **fourteen cases** -- twelve
  synthetic subjects plus two absent inputs -- and names every one on every run,
  because a figure that disagrees with what the tool prints is the defect #723
  exists to prevent. Four are shapes an unwatched guard accepts: the suppression
  **copied** outward rather than moved, one added **outside every condition** (in
  each spelling family, `-Wno-X`, `-wdN`, `/w` and `-w`, since a classifier that
  knew `/wdN` passed the rest), a subject that no longer adds `-pedantic`, and an
  MSVC arm that adds nothing.
  - **The sharpest instance of it is a mode a failing tool tells you to re-run in.**
    `check-e2e-helpers.sh --case NAME` ended in a literal `exit 0`, so a run printing
    `BUG: the bound is sleeping through commands that have already finished` and a
    healthy run were the same status -- and that mode is what the fixture's own
    failure block advertises, so the advice pointed at the one path whose verdict was
    hardcoded. A lane followed it, built a harness on the status and reported **6 of 6
    PASS** including a run that should have failed; nothing errored and the output was
    well-formed (#1104).
  - **A status that answers a DIFFERENT question is why such a thing survives.** The
    `exit 0` sat after the case returned, so the status did mean something -- *did this
    case run* -- and the five internal consumers read it correctly for exactly that.
    Nothing internal ever needed it to carry the verdict, which is why no test failed.
    Ask what a status ANSWERS, not whether it is read.
  - The fix applies the driver's OWN rule (the absence of `BUG:` from the output) to
    the same text, rather than adding a marker beside the printing: one rule and two
    readers, never two mechanisms free to disagree. THREE outcomes -- 0 clean, 3 ran
    and reported a defect, anything else aborted -- because *aborted* and *found
    something* are fixed in different places. And the wrapper is the mode the driver
    itself uses, or the mode under test is not the mode in use (#499's shape); that is
    pinned by a derived count of the self-invocations rather than a remembered one.

- **Verifying the FACT a check is about is not verifying the CHECK, and that is the
  version that feels like diligence.** The shape is always the same: you doubt an
  instrument, so you answer its question a second way, and report the agreement.
  **Two spellings of one question are two instruments, and only one of them was under
  test.** Validate a check by running *its* implementation, on inputs whose answer is
  already known. Six instances in one session, none of which errored and all of which
  produced well-formed output (#1093).
  - **`producer | grep -q` under `pipefail` is SIZE-DEPENDENT, so a small fixture
    reports it working.** That is why the idiom survives review, and why five files
    carrying comments explaining the defect went on spreading it. Measured, N=20 per
    row, pattern present on an early line:

    ```
    producer                                     correct   WRONG (status 141)
    git show e2e-common.sh   (101 KB)                 0      20
    git show .gitattributes  (1.1 KB)                20       0
    synthetic ~60 KB (just under the 64 KB buf)       2      18
    synthetic 200 KB                                  0      20
    herestring remedy, 101 KB                        20       0   (20/0 on true ABSENCE too)
    ```

    The premise the rule needs is that the producer must still be WRITING when
    `grep -q` exits; one that has already finished exits 0 and the pipeline is right.
    So *"it answers absent precisely because the content is there"* is true of a large
    file and false as a general law. The 60 KB row is the finding: one command, one
    machine, both answers. **Not reliably broken is worse than broken.** #970's remedy
    stands -- a HERESTRING, which is not a pipe.
  - **There is no blanket setting, because the option that makes one idiom lie is what
    makes the other tell the truth.** With `pipefail` OFF, `timeout ... | head -N` then
    `$?` reports **0** for a producer that really returned **124** -- success, for a
    command that timed out. With it ON, the same line reports 124. So the rule is not
    an option: **never read a pipeline's `$?` as a verdict about one member.**
    `PIPESTATUS` is what answers -- **and it has its own footgun, which is not optional
    to state, because recommending the remedy without it hands people a defective one.**
    `PIPESTATUS` is rebuilt by the next command, and a variable assignment is a command:

    ```
    read PIPESTATUS first:   1 0    (2 elements: producer failed, head succeeded)
    st=$?; then read it:     0      (1 element -- the ASSIGNMENT reset it)
    ```

    The wrong spelling yields a plausible one-element array, which is the same
    well-formed wrong answer this entry is about. Found while measuring the `| head`
    case *for this entry*.
  - **Run BOTH directions. Which one you skipped decides which way your instrument
    lies.** Skip the negative case and a content predicate fails toward *present / it
    merged*, the direction that gets **acted on**; skip the positive case and it fails
    toward *absent / refuted*, the direction that gets **believed**, because refuting
    reads as rigour rather than as convenience. Measured pair: a predicate for *has
    #1091 merged*, keyed on `Withdraw` in `CompileCacheWire.hpp`, answered **3
    occurrences on a master that did not contain it** -- all three the pre-existing
    `Withdrawn` error code, a background of **3 on both sides of the merge** -- while a
    rebase gate keyed on `_e2e_deadline_arm`, spelled `git show ... | grep -q` under
    `pipefail`, could only ever answer **NO**. A predicate that works is evidence about
    the **token**, never about the technique: the second discriminated only because its
    symbol happened to be new.
  - **Two instruments agreeing on the only case either has run is not corroboration.**
    That gate was "verified" by asking `grep -c` instead of `grep -q` and reporting
    0-on-master / 19-on-branch as confirmation. The two agreed on the one case both had
    run -- master, where the true answer is *refuse* -- so a coincidence was read as a
    second opinion. This tree already carries the mirror (*agreement between a fresh
    measurement and a source you have not read is worth nothing*); this is that rule
    pointed at instruments instead of sources, and it needs saying because "somebody
    checked it independently" is precisely what retires the suspicion.
  - **A guard whose only observed behaviour is refusal is indistinguishable from one
    that always refuses -- and a TRUE refusal is what makes it so.** That gate's
    refusal was correct on the day it was tested, which is exactly why nobody looked
    again. Watch it accept: that is the positive case, and it is half the obligation
    rather than the whole of it.
  - **The unit of validation is the READER, not the command and not the person.** In
    one command, two readers, and only one was sound: an explicit-ref
    `git show origin/master:<file> | grep -c` carrying its own positive control, and in
    the very next clause a grep of the **working tree** -- a primary checkout parked on
    `master`, 25 commits behind, reporting clean. Care in one clause bought nothing in
    the next, and the careless clause was the one being sent to somebody else as a
    correction. The stale-tree mechanism is already recorded above (*the tree you
    measured is not necessarily the tree in question*) and is not restated; what this
    adds is that a positive control on one reader says nothing whatever about a second
    reader on the same line. **And a reader that TRUNCATES is a reader too**: a `head -8`
    over 13 matching lines was reported as a complete enumeration, in the ticket whose
    own acceptance clause demands a derived answer (#1104) -- this tree's existing
    *a listing that came back AT its limit* rule, self-inflicted rather than imposed by
    a tool.
  - **And WHERE an instrument reports is not where the fault is.** A desynchronised
    scanner reports at the first construct it cannot reduce, which may be arbitrarily
    far from the cause and may be a line that is correct and unchanged. Measured:
    `e2e-helpers-selftest` died at PARSE in **0.02 s** on `macOS-clang-release` with
    `syntax error near unexpected token '('` -- at a line that **is on master too and
    parses there**, 135 lines downstream of the real fault. The cause was an apostrophe
    in a comment inside `$( )`: bash 3.2's command-substitution scanner does not skip
    comments, so `lane's` opens a single-quoted string as far as that scanner is
    concerned and swallows the closing paren. Five of them, an **odd** count. Reading
    the reported line is the natural move and it is wrong here. Bisected on a real bash
    3.2.39 rather than reasoned, because the two likelier-looking candidates are both
    innocent:

    ```
    function definition inside $( )            3.2 PARSES   5.2 PARSES
    multi-line single-quoted awk inside $( )   3.2 PARSES   5.2 PARSES
    backtick in a comment inside $( )          3.2 PARSES   5.2 PARSES
    apostrophe in a comment inside $( )        3.2 FAILS    5.2 PARSES
    ```

    **A TOKEN scan cannot see this and is not at fault**: the bash-3.2 scan checks
    `mapfile`, `declare -A`, `local -n`, `${var^^}` and passed correctly, because this
    is a composition of individually legal tokens -- a different question, not a missed
    one, and saying so is what stops the next reader distrusting the scan. That gap is
    #880; nothing in the tree parse-checks a script at all, which is #1100, and
    `check-table-totals.sh` already carries the same hazard through a different door
    (*"no apostrophes here -- it is a single-quoted shell string, and one ends it"*),
    three thousand lines from the file that needed it.
  - **And sometimes there is no right reader in that tool at all** -- a stronger claim
    than *pick the right one*, and the remedy is a different instrument rather than a
    better pattern. Measured, asking one question two ways on Git Bash:

    ```
    grep -c $'\r' <file>                     -> the LINE COUNTS: $'\r' expanded EMPTY,
                                                so the pattern matched every line
    CR=$(printf '\r'); grep -c "$CR" <file>  -> 0 on a KNOWN-CRLF file: text mode eats
                                                the CR before grep ever sees it
    ```

    Two spellings, opposite failure directions, neither erroring, both returning a
    plausible number. `od -c` and `file(1)` answered correctly; **on this platform
    `grep` cannot answer a line-endings question in either direction.** What caught it
    was **the number disagreeing with a fact already in hand**: those scripts had *run*
    under bash, and a CRLF `.sh` fails to start at all, so either the census was wrong
    or the runs were impossible. That cross-check costs nothing, needs no second
    instrument, and is the only thing in this family that catches an error *before* it
    leaves the room rather than after. The detector was then confirmed against a
    known-LF file **and** a known-CRLF file -- *watch it accept as well as refuse*,
    applied to a one-line census. A related unit error travels with it: a read-back
    showing **4916** against a local **4926** looks exactly like truncation and is not
    -- `jq`'s `length` counts CODEPOINTS where `wc -c` counts BYTES, and five em-dashes
    at two extra bytes each reconcile it to the byte. Resolve such a gap exactly, or
    the truncation question stays open forever.
  - **An instrument can be blind to the phenomenon by construction, and then its clean
    answer means nothing.** `gh api rate_limit` reports the GraphQL bucket as
    `5000/5000, used=0` while a live GraphQL call in the same minute returns
    `X-Ratelimit-Resource: graphql, Used: 5000, Remaining: 0` and refuses. So a
    `core 5000/5000` reading was used to rule out *lanes are spending a shared budget*
    and could never have seen it. **The correction is that the instrument was blind,
    NOT that the original guess was vindicated**: the live reading is from a different
    hour and that bucket resets hourly, so it establishes a mechanism and not a
    history. Taking the flattering half would be this same error pointed the other way,
    and it arrives as somebody handing you credit. The same call answers **HTTP 200**
    with the error in the BODY, so there the **exit code is the sound reader and the
    HTTP status is not** -- the two readers disagreed and the wrapper was the one that
    lied, which inverts the usual advice rather than replacing it.
  - **A scan cannot cover what is not in the repository, and that is the entire gap --
    no new check is proposed.** Measured against the real scan in four arms: the defect
    in an **untracked** `.sh` inside `scripts/` is **caught**; the same file tracked is
    caught; a tracked `.sh` **outside** `scripts/` is invisible to the `grep -q` scan,
    but `shell-walk-scope` **refuses the tree by name**, so it cannot happen silently
    (it was `bash32-scope` until #843 gave the walk more readers than that one scan
    and the name stopped describing what it answers for). The
    one blind spot is a script outside the repository -- a scratchpad file, which is
    where that rebase gate lived -- and no enumeration can reach it: untracked, outside
    every walk, gone by the next session. Widening the scan there is unsound rather
    than merely noisy, and that is stated so it is not re-proposed as an oversight. The
    remedy is self-testing by hand, in both directions.
  - **A comment sitting near a check is not that check's contract.** Found while
    auditing this very rule: the `git ls-files '*.sh'` comment belongs to the **scope
    guard**, and was read as the `grep -q` scan's file set -- producing a confident and
    wrong account of the coverage boundary, corrected only by running the four arms
    above. The mirror of this tree's *a COMMENT is not a call site*, and the same
    lesson: what settles a check's behaviour is the check, executed.

- **The copied case is why the difference is a COUNT and not a set.** A suppression
  added outside the block *and* left inside it is present at both `WERROR`
  settings, so as sets the difference is empty and the check passes -- permanently
  and by construction -- while its own refusal says *"move the flag, do not copy
  it"*. A guard that reads as enforcing something it cannot is worse than no guard,
  because the trailer sends people at the one shape it does not catch. Measured on
  the real subject with the copy planted: the membership form reports success, the
  counting form refuses by name.

- **And a selftest that matches a `FATAL_ERROR` must flatten its whitespace first.**
  CMake word-wraps that message at about 76 columns with indented continuations, so
  where a line breaks depends on the length of whatever is interpolated into it --
  and two of these messages begin with a PATH. Measured: with the selftest's scratch
  directory 17-24 characters one case failed, at 28-48 a different one failed, and
  at 52 or more both passed. `cmake -B /tmp/b` would have failed the test on a clean
  tree while this repository's own deep `out/build/<preset>` path passes, so CI
  stays green and only some developers see the red -- and what it prints accuses the
  check of drift when the only variable is `$PWD`.

## The portable compile-cache module

<!-- agent-tripwire: `cmake/portable/CompileCache.cmake` stays stock-CMake-only and must never fail a configure -->

- **`cmake/portable/CompileCache.cmake` must stay stock-CMake-only, and must never fail a
  configure.** Same constraint as `Cli/UsageDoc` and `Protocol/CompileCacheWire`,
  for the same reason: the file is *meant* to be copied verbatim into other
  projects, so a dependency on anything else here breaks it where nobody in this
  repository would notice. It is also included at `CMakeLists.txt:164`, before CPM
  is bootstrapped at `:183`, so `CPMAddPackage`/`FetchContent` are not available to
  it even locally — the `PACE_AUTO_INSTALL` fetch therefore uses bare
  `file(DOWNLOAD)`. Not with `EXPECTED_HASH`, which aborts the configure on a
  mismatch *even when `STATUS` is captured* (measured); the SHA-256 the release
  publishes is compared by hand instead, which is the same guarantee without the
  abort. Every other way the fetch can fail — unpublished platform, no network, a
  binary that will not run here — ends the same way, in one `message(STATUS)` and a
  fall-through, because a project that vendored this file to get a *faster* build
  must not lose the ability to build at all when GitHub is unreachable.
  `ctest -R compile-cache` covers both halves offline, the decline paths through a
  sandbox and the install path through a `file://` mirror.
  - **The ways it can fail a configure are not obvious, and two of them arrived in one
    change.** `check_<lang>_compiler_flag` is a hard `CMake Error` — "C: needs to be
    enabled before use" — for a language the project has not enabled, and this module
    is included from a `project()` that lists CXX first, so asking it unconditionally
    ended the configure outright. Ask `get_property(GLOBAL PROPERTY ENABLED_LANGUAGES)`
    first; a language nobody enabled also has no compile lines to put a flag on, so
    skipping it is right rather than merely safe. And a bad flag left in
    `CMAKE_<LANG>_FLAGS` fails the compiler ABI check, which is a configure failure
    too — so a flag is **checked** rather than gated on a compiler-ID string. `cl`
    answers an unknown `-f...` with warning D9002 and exits 0, so the check has to be
    kept away from it by the guard rather than expected to reject it.
  - **Anything this module computes and appends is a function, checked as a
    computation.** `_pace_debug_prefix_map_rules` + `ctest -R debug-prefix-map-rules`,
    which is in the default set and needs no compiler. The alternative is two
    ~40-second configures per layout, so the layouts that break it — out-of-tree,
    another mount, in-source — are exactly the ones nobody has locally and nobody
    tests. It was wrong twice before it was first RUN: `file(RELATIVE_PATH)` answers
    with a trailing separator, and out-of-tree it answers
    `../../mnt/d/.../checkout`, which is *relative* and carries the whole checkout
    path. **Relative does not imply machine-independent**, and a value that looks
    portable is worse than one that obviously is not.
## `USE_COMPILER_CACHE` in full

<!-- agent-tripwire: sccache is never selected AUTOMATICALLY (`ALLOW_SCCACHE_FALLBACK`, default OFF) -->

`USE_COMPILER_CACHE` (default ON, `cmake/portable/CompileCache.cmake`) fronts the compiler
with our own `pace-cc` when it is on `PATH` and a daemon answers — at
`127.0.0.1:6674` by default, or wherever `PACE_ADDR=host:port` points;
`PACE_SOURCE_DIR`/`PACE_BINARY_DIR` are injected from the source and build
trees. Configure proves the cache works by compiling one tiny file through the
launcher (~0.1 s) and requiring a `HIT`/`MISS`, because a launcher that cannot
reach its daemon still compiles fine and would otherwise cost every TU a failed
connect in silence. When nothing answers it falls through to `ccache`; `sccache`
sits between the two in preference order but is **opt-in**, see below. When
*nothing usable* is installed, `-DPACE_AUTO_INSTALL=ON` (default OFF) fetches a
prebuilt `pace-cc` for the host from the latest stable release instead,
staged per user so a machine downloads it once; `cmake/README.md` is the note
for projects vendoring the module. A cache hit reproduces only the object file,
so with either launcher active the module scan and precompiled headers are
turned off and MSVC debug info is forced to `/Z7`
(a modmap flag makes the launcher's preprocess step fail, and a PCH or shared
PDB is a second artefact no hit can reproduce).

- **An environment value SEEDS a build tree and never steers one** (`_pace_hold_setting`).
  `PACE_ADDR` and `PACE_SCHEDULER` are taken from the environment only by the
  configure that creates their cache entry; a later configure whose environment differs
  REPORTS it, naming the `-D` that would apply it, and applies nothing. Both used to
  retarget on an environment CHANGE unless the entry had been "changed by hand", judged by
  comparing it with the value last applied — which cannot see a `-D` that typed the value
  already held, `OptionSpec::explicitBit`'s blind spot in CMake, where nothing says a `-D`
  was on this command line. Measured: `-DPACE_SCHEDULER=`, typed to say OFF from a
  shell holding the variable, turned dispatch ON. And dispatch is baked into the launcher
  in BOTH states and said beside it (`_pace_dispatch_state`), because the launcher used to
  read it from whatever shell ran the build and 341 misses compiled locally in silence.
  `ctest -R compile-cache-dispatch` compares the printed line with every `LAUNCHER =` line,
  across reconfigures with and without a `-D` and across ninja's own regeneration. **Its
  decisions are a verdict on every host, so a decision failure ends the check FAILED and never
  beside its `SKIP: ` marker**: ctest lets `SKIP_REGULAR_EXPRESSION` outrank
  `FAIL_REGULAR_EXPRESSION` (measured, `***Skipped` and `100% tests passed`), and only the
  wiring needs a toolchain. `ctest -R compile-cache-dispatch-verdict` asks a nested ctest how
  a planted failure is scored under the registration's own two patterns.

- **Under MSVC and clang-cl the `sccache` fallback can silently produce a wrong
  build, and the configure warns about it now rather than leaving it to be
  discovered.** sccache replays a cache hit's `/showIncludes` stream verbatim —
  the **absolute** paths spelled by the build that *stored* it — while the text it
  hashes to find that hit carries no paths at all, because it preprocesses MSVC
  with `/EP` and `/EP` emits no line markers. Two checkouts therefore share
  entries and then record each other's headers as their dependencies. Measured on
  this repository: two worktrees at one commit, stock configure, no daemon —
  **137** cross-worktree cache hits, **1097** dependency edges recorded pointing
  at the *other* worktree and **none** at its own, and `ninja: no work to do`
  after a real edit to the checkout's own `Logger.hpp`.

  **GCC and Clang are not exposed, and the negative result is the reason the
  warning is scoped rather than unconditional.** Their preprocessed output carries
  `# n "path"` line markers, so with the absolute include paths CMake generates
  the hashed text differs between checkouts and there is no hit to replay
  (measured on Ubuntu 24.04 with g++-14: 0 hits, 2 misses). Spell the same compile
  with relative paths and there *is* a hit — but then the depfile is relative too
  and resolves inside the consuming tree. Self-consistent either way. A warning
  that fired on the majority of this project's CI, where it cannot happen, is one
  contributors would learn to skip.

  The symptom is not a stale build you notice. It is a green build and a crash
  somewhere unrelated: adding a virtual to `IStorage` linked objects compiled
  against the old vtable, and five `ShardedStorage` tests segfaulted inside `Get`.

  **It bites an incremental build across two checkouts that share one cache.** A
  clean build has no dependency graph to corrupt, and checkouts that all sit at the
  same absolute path replay paths that are correct — CI is normally both, and
  downstream projects run CI with no daemon reachable on purpose. That used to be
  the argument for the fallback staying automatic; **#815 overturned it, for a
  reason the hazard analysis could not see** — see the next entry. Passing
  `-DSCCACHE=` falls through to ccache, whose default empty `base_dir` means it
  does not rewrite absolute paths and so does not share entries between checkouts.

  `pace-cc` does not have this failure mode by construction — `MaterializeHit`
  runs every stored region through `PathCanon::LocalizeRegion` before replaying it,
  and `MissingReplayedDependency` refuses a hit whose replayed dependency is not
  there. That is the fix, not a workaround: install it and run a daemon, or
  configure with `-DUSE_COMPILER_CACHE=OFF`.

  A launcher's caveat is a **row in the candidate table** (`_pace_cache_<id>_caveat`),
  not an `if` on its name, and `ctest -R compile-cache-caveat` asserts both halves —
  that sccache warns, and that the launchers without a hazard stay silent. A warning
  that fired for every launcher would be one nobody reads.

- **sccache is never selected automatically, and a version refusal is announced
  rather than reported (#815).** Two rules, one defect, and the second is the half
  that survives the first.

  The reporting host ran a packaged `/usr/bin/pace-kv` 0.1.0 while
  `/usr/local/bin/pace-cc` was a current build. Wire 3 against a server
  speaking 1..1 — correct on both sides, a deployment mismatch and not a bug — so
  every exchange was refused, `CompileCache.cmake` fell through, and the project
  built through sccache for weeks while believing it dogfooded its own launcher.
  **Every mechanism worked.** The launcher degraded exactly as designed, recorded
  the refusal, and tallied it in `--show-stats` (1003 compiles, 2.1%, reaching no
  cache). The configure's own probe passed the fallback silently because it tests
  **reachability, not acceptance** — it accepts a `HIT`/`MISS` and a refusal is
  neither, so the row was skipped at `STATUS` among a hundred other status lines.

  - **The gate.** `_pace_cache_sccache_requires` is `${ALLOW_SCCACHE_FALLBACK}`,
    default OFF — a value in a column that already existed, not a branch. Opted
    into, sccache keeps its rank above ccache, because asking for it is asking for
    it. The alternative remedy — have CI set `CMAKE_C/CXX_COMPILER_LAUNCHER`
    externally — would have worked and is **wrong**: this module returns early when
    a launcher is already set, so it would have taken the `/showIncludes` caveat
    warning above out of the log with it, silently, on exactly the platform where
    that hazard exists. Gating the row keeps the warning. The option name carries no
    project prefix, like `USE_COMPILER_CACHE`, because the file is vendored verbatim.
  - **The three Windows jobs opt in**, and that is a hard requirement rather than a
    convenience: `windows`, `compile-cache-e2e-windows` and `package-windows` front
    the compiler with sccache and measured 80–99% hit rates. A job that lost the flag
    would compile *cold*, not break — which is the failure CI is worst at noticing —
    so the existing `compile_requests -eq 0` assertion in all three is what catches
    it. That assertion is the guard; there is no separate check.
  - **Dropping sccache does not end the silence, it RELOCATES it.** On the reporting
    host ccache is installed, so the same refusal now falls through to ccache with
    the same absence of announcement. So the second rule: a rejection whose reason
    matches the row's `predicts` column is a `message(WARNING)` **whatever replaced
    it, including nothing**. #658 had already built the machinery and conditioned it
    on the winner carrying a caveat — which is a property of the COMPILER, true on
    MSVC and clang-cl and false on GCC and Clang — so on the host that filed #815 it
    was silent by construction. Three replacements, three wordings, one warning:
    safe, hazardous, and none at all. The last is the loudest, because the build then
    compiles uncached, and it is the one that used to emit nothing at all: the loop
    lived inside `if(_pace_cache_chosen)`.
  - **A `message(WARNING)`, never `SEND_ERROR`.** The module may not fail a
    configure (its own header, and `check-compile-cache-caveat`'s "a caveat must
    never fail a configure" row), and a daemon out of step with a launcher is the
    normal state during a rollout. A warning is the loudest level that leaves the
    build buildable, and that is the whole of the decision.
  - **The remedy names the direction**, which is #815's clause 2. `unsupported wire
    version 3; this server speaks 1..1` is accurate and stops one step short of
    *your daemon is older than your launcher* — and it cannot be fixed where it is
    written, because the sentence comes from the **daemon**
    (`CompileCacheHandler.cpp`), so an old daemon goes on sending the old wording
    forever. It is read at `_pace_cache_pace_cc_predicts_detail` instead.
  - **A launcher installed and not used is announced too.** A row skipped because
    its `requires` is falsy used to print nothing, which would have rebuilt #815's
    shape one row over the moment sccache became opt-in. `_pace_cache_<id>_requires_note`
    is the column; a row whose absence explains itself carries none, which is why
    `pace_cc` has none — an emptied `PACE_ADDR` is a documented opt-out
    (#372).
  - **Auto-install had to move with it.** `PACE_AUTO_INSTALL` fires only when
    nothing else is installed, on the reasoning that "a launcher the user installed
    is a decision already made". An installed-but-not-opted-into sccache is not that
    decision, and counting it as one would leave a machine that explicitly asked for
    auto-install with no cache at all.
  - Coverage: `ctest -R version-fallback-warning` drives the decision as a pure
    function over eleven rows (the situation needs two binaries at disagreeing wire
    versions, so it cannot be staged), and `ctest -R compile-cache-caveat` drives the
    gate through real configures in both directions — opt-in absent and sccache
    passed over even with ccache present beside it, opt-in set and sccache selected
    with the caveat still printed. Both were shown failing against the pre-#815
    module before being believed.

- **The same hazard has a second audience, and that warning cannot reach it.**
  Pointing sccache at a pace-kv daemon — `SCCACHE_MEMCACHED` / `SCCACHE_REDIS`,
  which `README.md` pitches, the docs repeat and this project's own `--help` prints
  — is *definitionally* **one cache shared by every checkout and every machine
  pointed at it**, the maximal form of the entry above. Those users have their own
  build system and never configure `CompileCache.cmake`, so the `message(WARNING)`
  it emits never happens to them.

  Measured here in two compiles per compiler, which is all it takes: with sccache
  0.14.0 and MSVC 14.51 a second directory took a **cache hit from the first**, and
  its `/showIncludes` named the *first* directory's header; under g++ 14 the same
  two compiles were **0 hits and 2 misses**. `README.md` had asserted the opposite
  — that sccache's entries are "not portable between checkouts at different paths"
  — which is true of GCC and Clang and **false of the exact compilers that are
  exposed**, so the one caveat that was there read as reassurance. Silence would
  have been better than that sentence.

  `docs/snippets/sccache-backend-caveat.md` is the one wording; the MkDocs pages
  include it, and `README.md` and `--help` restate it because neither can include
  anything. `ctest -R sccache-backend-caveat` fails any file naming either variable
  without, within 40 lines of it, the three facts a reader is otherwise right to
  skip past: **which compilers**, **the mechanism** (`/showIncludes`, `/EP`), and
  **the remedy** (`pace-cc`). Wording is free; those three are not. Prose
  drifts exactly the way an include graph drifts — nothing fails, nothing warns,
  and the next page pitching it is written by someone who never saw the caveat on
  the other four.

## Running the launcher is not testing it

<!-- agent-tripwire: Running the launcher is not testing it. The synthetic fixtures prove it RUNS -->

`compile-cache-e2e` and the `pace-cc smoke` job compile synthetic single files
and never execute what came out, so they prove the launcher **runs** and produces
**an** object — not that it is the **right** object. That gap is why #319 (a
cache-backed build segfaulting while the same commit at `-DUSE_COMPILER_CACHE=OFF`
passed) could only be found by a developer noticing a crash, and why #368 could
recur with nothing reporting it.

`scripts/launcher-replay-e2e.sh` closes it by building a real target three times —
a cache-off **control**, a **cold** build that stores, a **warm** build that
REPLAYS — and running the replayed binary's own tests. Replay is where a wrong
object comes from, so a fixture that only builds cold tests nothing.

- **Objects are compared cold-against-warm, never control-against-warm.**
  `CompileCache.cmake` disables PCH and module scanning when a launcher is active,
  so a cache-on and a cache-off build are configured differently and their objects
  legitimately differ. Cold against warm is the only apples-to-apples comparison
  available, and it is the one that matters. The control participates at the level
  it can: its suite result must agree.
- **Two guards make a green run mean anything.** The cold build must be observed
  USING the launcher (`LAUNCHER = ` in `build.ninja` — the same check the standing
  `-DUSE_COMPILER_CACHE=OFF` rule is verified by from the other side), and the warm
  build must be observed HITTING. A warm build that missed everything compiles
  correctly, passes every assertion, and has replayed nothing.
- **Injecting a wrong object needs the linker, not `touch`.** The obvious staging —
  replace the `.o`, touch it so it looks newer than its source, rebuild — does not
  work under ninja: ninja records each output's mtime in `.ninja_log`, so a replaced
  object reads as **dirty** and is **rebuilt**, silently undoing the injection and
  leaving a canary that always passes. The first version of that canary did exactly
  that, and a throwaway probe on a five-line project caught it in seconds. Take the
  link command (`ninja -C <dir> -t commands <target> | tail -1`) and run only that.
  It bypasses the dirty check and is also the truer simulation: a wrong cached
  object is one the build system has no reason to touch again.

## Code coverage

<!-- agent-tripwire: Coverage is Clang source-based, never gcov: ~2000 Catch2 cases are ~2000 processes -->

`cmake --preset clang-coverage`, build, then `--target coverage`. That target runs the
**whole** CTest suite under instrumentation and writes
`out/build/clang-coverage/coverage/`: `html/index.html` to browse, `coverage.lcov` for
Codecov, `report.txt` and `percent.txt`. CI runs that same target, so there is one code
path (`scripts/coverage.sh`) rather than two that drift.

**Clang source-based, never gcov — because of how many processes this suite is.**
`catch_discover_tests` gives each of ~2000 `TEST_CASE`s its own process, and the
script-driven tests spawn daemons and launchers besides. gcov merges counters into a
shared `.gcda` per object file as each process exits, so concurrent writers race; that
race is what every `lcov --ignore-errors mismatch,inconsistent` on the internet is
suppressing, and a suppressed error there is under-counted coverage reported as a clean
run. LLVM keys each raw profile on the binary's own module signature and merges into it
under a lock, so no suppression and no serialization is needed.

**`%8m`, never `%p`.** Measured on this tree, 2228 test processes produce **55** raw
profiles totalling 20 MB. `%p` would have written one multi-megabyte file *per process*.

**A compiler cache and coverage cannot be combined.** Coverage mapping data is embedded
in the object file and names its sources by **absolute path**, while `pace-cc`
exists precisely so an object built under one checkout root can serve a compile under
another. A hit replays a perfectly valid object carrying the *producer's* paths, and
llvm-cov then reports files that do not exist here — a report about somebody else's
tree, with nothing failing to say so. The preset sets `USE_COMPILER_CACHE=OFF`, and
`cmake/Coverage.cmake` refuses to configure if a launcher is set anyway, since
`-DCMAKE_CXX_COMPILER_LAUNCHER=` bypasses that option.

**`*_test.cpp` is excluded from the report, and that is load-bearing.** Tests here live
*next to* the implementation, so ~150 `*_test.cpp` files compile straight into the test
binaries. Counting them measures the tests testing themselves — thousands of near-100%
lines that move the total a long way and mean nothing. The one `ignore_regex` in
`scripts/coverage.sh` is the single source of truth for what is measured; `.github/codecov.yml`
restates it only so Codecov's view cannot silently disagree.

**Every misconfiguration is a `FATAL_ERROR`, not a warning that disables itself.** A
non-Clang compiler, Windows, an enabled sanitizer, no test suite, a missing `python3`, a
compiler-cache launcher, or an `llvm-profdata` whose major version differs from the
compiler's — the raw profile format is versioned, and a mismatch otherwise surfaces as a
complaint about the *file* rather than about the tool. A coverage build that quietly
instruments nothing still compiles, still runs the suite and still writes a report, so
every signal an author would check says it worked. Same reasoning as the sanitizer entry
above, which had already been found in exactly that state.

**And "a missing `python3`" means one that does not RUN, which is not what the obvious
lookup asks** (#568). `find_program(NAMES python3)` returns the first name match on PATH
and never executes it; `find_package(Python3 COMPONENTS Interpreter)` validates by running
it. Measured on Windows with CMake 4.3.1, one tree, one configure: `find_program` selected a **0-byte** Windows App
Execution Alias — a reparse point Windows puts on PATH that refuses to execute when no
Store package backs it — while `find_package` produced a real **171744-byte** interpreter.
**Attach the right mechanism to that second half**, because the obvious reading of it is
wrong and the wrong reading is the useful-sounding one: the working interpreter was NOT
further along the same PATH, it was not on PATH at all, and FindPython reached it through
`Python3_FIND_REGISTRY` (registry first, on Windows only). On the POSIX legs there is no
such second source — measured on CMake 3.28.3, `find_package` stops at the FIRST name
match, validates it, gives up, and does not go on to a working `python3` or `python3.12`
later on the same PATH. So what this buys is **validation, never better selection**, and
a rule claiming otherwise would be cited into a design that cannot work.

What validation is worth on its own is the whole point: reproduced end to end on Linux
with a `python3` that cannot exec, the old spelling put it in the `coverage` target's
command line and configure SUCCEEDED — the late failure the gate exists to prevent, let
through because the gate tested presence rather than function. The trade is deliberate and
has a cost worth stating: a broken shim early on PATH now refuses the configure outright
where it used to configure and fail at the end of the run, so the diagnostic must name
`-DPython3_EXECUTABLE=` or it strands an operator who has a perfectly good interpreter
installed. Guard on `Python3_Interpreter_FOUND` and never `Python3_EXECUTABLE` —
FindPython leaves the latter naming the candidate it just rejected, so the tidier spelling
restores the bug.

The rule generalises as *a tool the build will EXECUTE is located by something that
executes it*, and it has **reasoned exceptions that must not be "fixed"**. `find_package`
needs a toolchain, so `cmake/Version.cmake` cannot use one — it runs before `project()`,
and says so. Where no validating find module exists, validate by running: the two
`llvm-*` lookups in `cmake/Coverage.cmake` do, and `cmake/Packaging.cmake` and
`cmake/portable/ClangTidy.cmake` do not, which is unexamined rather than decided. The two
shell fixtures that locate python (`scripts/tidy-sweep.sh`,
`scripts/launcher-replay-e2e.sh`) use `command -v`, which does not run it either; shell
has no validating equivalent and both run only on the POSIX legs. **Nothing enforces any
of this** — it is four names in a comment, not a closed set — which is
[#607](https://github.com/LASTRADA-Software/pace/issues/607).

**The CI job publishes and gates on nothing.** `coverage` in `build.yml` reports the
figure to the job summary, uploads the HTML, and pushes lcov to Codecov once
`CODECOV_TOKEN` exists; both Codecov statuses are `informational`. The long-term target
is >90% and raising it is separate work — a threshold added before anyone has had the
chance to move the number only teaches everyone to ignore the signal. A failing suite
still gets its report rendered, to read while debugging, and then re-raises so no number
measured from a red build is published.

## Scoping the matrix to what a change can affect

<!-- agent-tripwire: A `paths-ignore` filter on a workflow whose checks are **required** makes a pull request unmergeable, not fast -->

**A `paths-ignore` filter on a workflow whose checks are REQUIRED converts "slow"
into "unmergeable".** Master here is protected by a ruleset (`default-master`,
enforcement `active`), not by classic branch protection — so the
`/branches/master/protection` endpoint answers `404 Branch not protected`, and
anything reasoning from that endpoint is reading a lie. Its required contexts are
`RequiredContexts` in `scripts/check-merge-queue-contexts.sh`, which every tool
that needs them reads — this paragraph used to enumerate them and went stale the
moment two were promoted (#408, #629), which is the *count* problem in its worse
form: **a stale list reads as complete**, so a leg checked against it is concluded
unrequired rather than merely miscounted. A workflow-level path filter stops the
workflow from triggering, so no check run is ever created for any of those, and the
pull request waits on a context that will never arrive.

A **job-level** `if:` is a different mechanism: the job is created and reports a
`skipped` conclusion, which a required check accepts. That is what
`.github/workflows/build.yml` does — one `changes` job publishes `code=true|false`
and every heavy job is gated on it.

- **The classification is `scripts/ci-scope.sh`, not a YAML glob**, so it is
  testable without a runner: `ctest -R ci-scope` runs its table against a
  throwaway git repository, in both directions. A glob living only in workflow
  YAML is a rule nobody can exercise until it is wrong in production.
- **Every way of not knowing escalates to "build everything".** An unresolvable
  ref, a failed diff, an empty diff, a path matching no row — all `code=true`,
  for the reason `tidy-sweep.sh` states about its own base ref: *we could not tell
  what changed* must never read as *nothing did*. The cost of being wrong that way
  is a matrix run nobody needed; the cost of being wrong the other way is a merge
  no job ever compiled, with every required check green.
- **`mkdocs.yml` is code and `.agent/**` is not**, which is the kind of judgement
  that has to be written down: the Documentation workflow builds the former
  `--strict`, while the rulebook is read by people and sessions rather than by any
  job. If a rule file ever generates something, it stops being documentation.
- **The cost this removes is not one matrix run per pull request.** The ruleset
  sets `strict_required_status_checks_policy: true` — branches must be up to date
  before merging — so every merge puts every other open pull request behind and
  forces a rebase and a full re-run. The matrix is therefore paid once per pull
  request *per merge that lands while it is open*, and that multiplier is the
  larger half of the argument.
- **A skipped MATRIX job never expands, so its per-leg contexts never exist.**
  This is the trap inside the fix, and it was found by probing rather than by
  reading: with a job-level `if:` on `linux` and `windows`, a docs-only run
  reported one context literally named `Linux-${{ matrix.preset }}` and another
  named `Windows-${{ matrix.preset }}` — while the four names the ruleset actually
  requires (`Linux-clang-release`, `Linux-gcc-release`, `Windows-cl-release`,
  `Windows-clangcl-release`) reported nothing at all. That is the same
  never-arrives failure as `paths-ignore`, reintroduced one level down, and every
  non-matrix job skipping correctly is what makes it easy to miss. So a matrix job
  is gated on its **steps**: the job starts, the matrix expands, each leg reports
  under its real name, and no step does any work. It costs one runner start per
  leg and buys the only thing that matters.
- **Three of those steps already carried an `if:`, and the gate silently vanished
  from them.** That is the duplicate-key trap recorded under the local gate above,
  met here for the first time: YAML keeps the last of two `if:` keys, so merge into
  `gate && (original)` rather than stacking, and scan for adjacent `if:` lines.
- **A gated job must still gate the release.** `check-release-gate` asserts
  statically, with `yq`, that every job key appears in `release.needs`; it never
  asks whether a job ran, so a job that no-ops on a docs change still counts. The
  `changes` job is itself a row there. On a tag or a push the classifier answers
  `code=true` unconditionally, so nothing is ever skipped underneath a release.

## A merge queue is a third door to the same never-arrives failure

<!-- agent-tripwire: A **merge queue** is the third door to that same never-arrives failure -->

`strict_required_status_checks_policy: true` means every merge puts every other
open branch behind, so the matrix is paid once per pull request **per merge that
lands while it is open**. Measured: 77 `build.yml` runs to land about ten pull
requests in one night, 25 of them cancelled. A merge queue is what that shape
calls for.

It is not a ruleset checkbox. **A merge queue dispatches the `merge_group` event,
and a workflow that does not listen for it produces no check run at all** — so a
required context never reports and a queued pull request does not fail, it sits
there. Same failure as `paths-ignore` above, third door. And it presents as the
feature working, right up until the first pull request enters the queue.

- **Both workflows must trigger on it, not just the obvious one.** `Require a type
  label` is required and lives in `pr-labels.yml`, which is `pull_request_target`
  — an event a queue **does not produce at all**. That is not a missing row in an
  `on:` list; the whole workflow is built around an event that is not there, for
  the security reason its header states, which must not be undone. The gate job
  therefore runs on both events and its queue leg says what it checked.
- **What a queue leg may legitimately assert is narrower than what a pull-request
  leg asserts, and it has to SAY so.** The queue branch is
  `gh-readonly-queue/master/pr-<n>-<sha>`, so the pull request can usually be
  recovered and the label re-checked for real — which catches the one thing entry
  to the queue cannot, a label removed while the entry was waiting. When the ref
  names none, that is stated and the leg passes on what entry proved. A leg that
  passes because something else already checked is fine; a leg that passes and
  does not say why is a stub, and reads exactly like a working gate.
- **A skipped job REPORTS, and a skipped required context is read as passing.**
  Measured here, on the head of the docs-only #356 (`b4777aa`): `Check C++ style`,
  `clang-tidy` and `macOS-clang-release` — all three required — each produced a
  check run with `conclusion: skipped`, and the pull request merged. The opposite
  claim is *also* true, of a different situation, which is why both get made: a
  skipped **matrix** job never expands, so its per-leg contexts never exist and
  nothing reports at all. On that same commit `Linux-*` and `Windows-*` came back
  `success`, because those are gated on their steps for exactly that reason. One
  hangs, one passes; the difference is the matrix.
- **And the converse, which is worse: a GREEN required context is not evidence that
  anything ran.** The bullet above ends at the skip. Finish the thought, because the
  two errors point the same way and an audit by conclusion is therefore wrong twice
  over. Measured on the docs-only #585 (run `33688370443`): `Linux-clang-release`,
  `Linux-gcc-release`, `Windows-cl-release`, `Windows-cl-debug` and
  `Windows-clangcl-release` all reported **`success`** in **3-9 seconds each**, with
  every step inside them skipped — `actions/checkout` included, so not one of them
  even had the tree. The whole run was about **38 runner-seconds**. Nothing was
  compiled, nothing was tested, and five required contexts went green saying so to
  nobody.

  That is the anti-hang design working exactly as intended and is not a defect: a
  matrix job must not be skipped at the job level, so `linux` and `windows` are
  gated `if: !cancelled()` with all ten of their steps gated on the scope instead.
  The defect is only ever in the READING. A skip at least looks unusual in the UI
  and invites a second glance; a green check looks precisely like the thing you
  wanted, so the wrong conclusion is the comfortable one. **The only discriminator
  is opening the job and reading its step list** — `conclusion` cannot carry this,
  in either direction, and no count of green contexts can either. Ask "did CI
  exercise this change" of the steps, never of the checks.
- **So a dependency's failure must not be allowed to skip a required gate.**
  `apply` is skipped inside a queue — there is no pull request to label — and a
  skipped dependency skips its dependents by default, which by the above is not a
  stall but a **stub**: green, and indistinguishable from a working gate. The same
  holds when `apply` *fails*: a condition excluding that result skips the gate, the
  skip reads green, and a pull request with no `type/` label becomes mergeable
  because the labeler broke. `Apply derivable labels` is not itself required, so
  nothing else closes it. The gate does not need `apply` to have succeeded — it
  reads the labels **fresh** from the API, so a human-applied label is readable
  either way — so the condition is `if: ${{ !cancelled() }}` and the gate checks
  for real. `!cancelled()` and not `always()`, which runs even when the run is
  being cancelled; any status function already overrides the `needs:` success
  requirement.
- **Check the concurrency key.** `pr-labels-${{ github.event.pull_request.number }}`
  collapses to the constant `pr-labels-` on `merge_group`, and with
  `cancel-in-progress` each queue entry then cancels the one before it. A
  cancelled required context is not a reported one. `build.yml`'s key is
  `github.ref`, which inside a queue is the temporary branch and is already unique
  per entry — but that is now load-bearing rather than incidental.
- **State the event in the scope classifier rather than letting it fall through.**
  `merge_group` reached `code=true` through the `changes` job's non-pull-request
  default. Correct, by accident, with nothing recording that anything depended on
  it. A merge candidate builds everything **by design**: it could be scoped, since
  `merge_group.base_sha...head_sha` is a real diff, but a batched group is built on
  top of the entries ahead of it, and the saving is one matrix per *merged* pull
  request — not the re-runs this queue exists to remove.
- **A failing queue entry is ejected, not merged, and the branch is fine.** GitHub
  removes the pull request from the queue, comments on it naming the failed check,
  and deletes the temporary branch; the pull request's own head is untouched and it
  can be fixed and re-queued. Nothing needs cleaning up by hand. The one thing to
  know is that the failure is reported on the *queue* run, so a red check on a
  merged-looking pull request wants the `merge_group` run, not the `pull_request`
  one.
- **Adding a JOB to `build.yml` for this would drag the release behind it**, since
  `check-release-gate` asserts every job there appears in `release.needs`. So this
  is triggers and existing jobs only — which is also why `pr-labels.yml` is a
  separate workflow in the first place, as its own header records.
- **And the workflow must not invert its own script's principle one level up.**
  `ci-scope.sh` says every way of not knowing escalates to `code=true`. The
  workflow reading it said `if: needs.changes.outputs.code == 'true'`, so a
  `changes` job that **failed** published no output, the comparison was false,
  sixteen jobs were skipped — and by the measurement above a skipped required
  context reads as passing, while `changes` is not itself required. A green,
  mergeable pull request that nothing had compiled: exactly what `ci-scope.sh`'s
  own header warns about, arriving through the workflow rather than the script.
  Every condition is now `!= 'false'`, so *did not answer* means build-everything,
  and every job that consults the classifier carries `!cancelled()` so a failed
  dependency cannot skip it before its condition is read.

  **The repository had been relying on the matrix trap to save it here, and no
  longer is.** With `linux` and `windows` step-gated and carrying no job-level
  condition, a failed `changes` skipped them too — and being matrices their
  per-leg contexts never existed, so the pull request *hung* instead of merging
  green. That accident was the only thing standing between a dead classifier and
  a merged, uncompiled change. Both matrix jobs now carry `if: ${{ !cancelled() }}`,
  which is the one job-level condition on a matrix job that is safe: it is false
  only while the run is being cancelled, so the matrix **always expands and every
  leg reports under its real name** — the exact opposite of relying on
  non-expansion. **The dependency on the accident is gone, not reduced.** Do not
  reintroduce a job-level `if:` on either believing the accident is still there to
  catch you — it is not, and it never should have been load-bearing.

  `ctest -R gated-jobs-fail-safe` (`scripts/check-gated-jobs.sh`) asserts both
  rules, derived from the workflow rather than tabulated, so the seventeenth job
  cannot be added wrong. `release` needs `changes` too and is excluded by
  construction: it never reads the classifier's output. What it proves is the
  **shape** of the conditions — the `changes` job cannot be made to fail on
  demand, so the behaviour it relies on is the `b4777aa` measurement above rather
  than a demonstration.

`ctest -R merge-queue-contexts` (`scripts/check-merge-queue-contexts.sh`) asserts
all of it from the workflow files, because the property cannot be demonstrated
before the fact: a `merge_group` event only exists once a queue is enabled, and a
queue that stalls is the outcome being avoided. It derives which job produces
which context rather than tabulating it — a second hand-written list is not a
cross-check, it is a second thing to be wrong — and the only copied datum is the
required-context list itself, whose provenance and the `gh api` call that reads
the live one are in the script header.

### A CONFLICTING pull request dispatches nothing, and that is the fourth door (#1068)

The three above are a workflow saying *do not run*: a `paths-ignore` filter, a
`branches:` filter, a missing `merge_group:` row. Each is found by reading the
workflow, and each is fixed there.

**This one is not.** The workflow configuration is correct, and the run cannot exist:
a `pull_request` workflow runs off the MERGE REF, GitHub cannot compute one for a
conflicting pull request, so it dispatches nothing at all. Twelve required contexts
are then **absent** — not pending, not failed, not skipped. A reader who checks all
three documented doors finds all three correct and is no closer, which is what makes
it worth its own entry rather than a sentence appended to theirs.

Measured on one pull request, same workflow configuration, two heads:

<!-- table-total: none -->

| head | `mergeable` | `Build [pull_request]` |
|---|---|---|
| conflicting | `CONFLICTING` / `DIRTY` | **none**, on `opened` AND on `reopened` |
| rebased | `MERGEABLE` / `BLOCKED` | queued within one second |

The `reopened` half is what makes it a property of the STATE rather than a dispatch
that was dropped once: closing and reopening while still conflicting produced the
label workflow again and still no `Build`.

- **The asymmetry is the whole tell, and it points the wrong way.** `pr-labels.yml`
  is `pull_request_target`, which runs off the BASE and therefore needs no merge ref
  — so it reports normally throughout. One workflow reporting while twelve contexts
  are missing reads as *CI is slow*, not as *this cannot merge*. Nothing on the pull
  request page says otherwise; there is no red, because there is no run.
- **A conflicting branch is silent in BOTH directions**, which is why it can sit for
  a long time. There is no run to fail, and there is no signal that no run exists.
  The lane that pushed it has no reason to look, and the manager notices only when a
  context count reads oddly beside its siblings. Neither party is watching the thing
  that would tell them. The count is the cheap version of that glance: **2 contexts
  where every sibling pull request that night had 26**, which needs no API call a
  conflicting pull request would answer differently.
- **The diagnostic ORDER is the part that saves the time.** Contexts **absent**
  rather than pending is the signal to ask `mergeable` FIRST, before reading a
  workflow. Twenty minutes went into re-checking `paths-ignore`, the `branches:`
  filter and the `merge_group:` row on the run that produced this entry; all three
  were correct, and correctly documented, and none of them was the answer.
- **Cheapest tell that needs no pull request at all: `git merge-tree --write-tree
  <branch> origin/master`.** It answers the same question locally, on PUSH, before a
  pull request exists — where the context count needs the pull request and needs
  somebody to notice an absence, and `mergeable` itself reports `UNKNOWN` for a
  window after every push, which is indistinguishable from a state nobody asked
  about. A lane can check its own branches in one loop.
- **`src/tests/CMakeLists.txt` is where this arrives.** Every check registers at the
  end of that file, so two lanes landing checks in one evening collide there by
  construction; it is the file that produced this instance. That is an argument for
  checking the state on push rather than for a convention about where to append,
  because the append point is not the problem — the collision is ordinary and the
  invisibility is the defect.
- **Resolving it, the marker scan is not enough.** This repository sets
  `merge.conflictStyle = diff3`, so a conflict has FOUR marker kinds and a
  three-way grep reports "0 markers left" over a file containing a literal
  `|||||||` line — which then fails the configure on every leg. Assert the ORDERING
  of the four (`<<<<<<<` before `|||||||` before `=======` before `>>>>>>>`) rather
  than counting them: a count answers "is this conflict shaped the way I expect",
  where the ordering turns a nested or rearranged one into an abort instead of a
  silent mis-resolve. And the check that actually proves the resolution is
  `git diff origin/master HEAD -- <file>` having **no deletion lines**: it catches
  losing the other side AND a stray marker, both as additions that are not yours,
  where a marker scan sees only the second and only when it knows to look for it.

### A pull request that BECAME conflicting keeps its verdicts, and reads the opposite way (#1352)

The section above is right about DISPATCH and silent about RETRACTION. A conflicting pull
request dispatches nothing from the moment it conflicts; it does not take back what was
dispatched before that. So there are two conflicting states, and they read as opposites:

<!-- table-total: none -->

| it conflicted | its required contexts show | the conclusion they invite |
|---|---|---|
| before its head was pushed | **absent** -- no run exists | *nothing is known about this branch*, which is true |
| after its head was pushed | **stale verdicts with real values**, from runs made while it still merged | *nearly green*, which is false |

Measured on #1333: `mergeStateStatus` `DIRTY`, the branch 49 commits behind master, and
30 contexts reporting -- 27 `SUCCESS`, 2 `SKIPPED`, 1 `FAILURE`. The failure was a
`clang-tidy` run on head `44fe4a59` that had completed nine hours earlier, and it is still
attached to that SHA.

- **Absent looks like nothing; a stale verdict looks like information.** And the green half
  is the dangerous half: a red invites investigation, a green invites merging. This cost a
  wrong handover -- a pull request described as having dispatched nothing, whose contexts in
  fact carried nine-hour-old values a lane acting on that description would have read as
  current.
- **So the discriminator is the pull request's state, asked FIRST, never its contexts.**
  `gh pr view <n> --json mergeStateStatus,mergeable`: `DIRTY` or `CONFLICTING` says every
  context below it describes a head that does not merge, whatever the context reads. The
  ordering advice above already points here; this is the state where skipping it costs most.
- **Neither cheap tell survives this state.** The context COUNT looks normal, because the old
  runs are all still there. A context's completion time is a tell only against the head's
  push time, which nobody has in hand -- and `gh`'s `completedAt` is `0001-01-01T00:00:00Z`
  for a run still in progress, so sorting on it ranks a superseded failure above its live
  replacement. Order runs by START time.
- **`scripts/ci-pr-required.sh` answers the merge question, on its own line.** It reads
  contexts at the head SHA, and a context is never retracted, so its `every required context
  reports SUCCESS` was a true statement about a commit and silent about whether that commit
  merges -- the dangerous green, from the script every lane verifies CI with. It now reads
  REST's `mergeable_state` and `mergeable` from the same response as the head SHA, prints a
  `merge:` line beside `states:` and a separate `MERGE VERDICT:`, qualifies the context verdict
  for a head that conflicts, is behind or is not yet computed, and exits 0 only when the
  contexts are green AND the head neither conflicts nor lags. `unknown` is its own outcome, a
  pull request no longer open is a record rather than a question to ask again, and a state its
  table does not name is refused by name.

## A gate that does not report reads as a gate that passed

<!-- agent-tripwire: A gate that does not REPORT reads as a gate that passed -->

The three doors above are all about a required context that never arrives. These
two are the same disease with the *required* clause removed, and they were found
together because they are one shape: **a failure nobody is shown is
indistinguishable from a success.**

### A non-required job failing in a merge group is reported nowhere (#684)

The queue holds on the required contexts and on nothing else, which is
correct — the packaging and coverage jobs are deliberately unrequired because
they are slow and because a packaging failure should not block ordinary work.
What is *not* correct is that such a failure reaches no surface at all: the pull
request page is green (its own run passed on the head), the queue reports success
(every required context passed), master is green afterwards (the same job passes
on the merge commit), and the only trace is an `event=merge_group` run that no
part of the normal flow ever lists.

**Measured, over every failing `merge_group` `Build` run the API still held on
2026-09-04 — six of them:**

<!-- table-total: of them=rows -->
| run | failing job | required? | pull request |
|---|---|---|---|
| 33783939363 | `Code coverage` | no | #689 merged |
| 33782559943 | `macOS-clang-release` | **yes** | #686 ejected, fixed, merged |
| 33760836218 | `Windows-cl-debug` | no | #667 merged |
| 33749317968 | `Package (macOS .pkg)` | no | #669 merged |
| 33665118078 | `Package (macOS .pkg)` | no | #546 merged |
| 33650121718 | `Windows-cl-debug` | no | #539 merged |

Five of six, four distinct jobs, five pull requests merged with nobody told. The
one required failure behaved exactly as designed, and that contrast is the whole
argument: this is a **reporting** gap, not a gating one, and closing it must not
turn those jobs into gates by the back door.

- **The unit is the CONTEXT, never the job key.** `Windows-cl-debug` is a leg of
  the same matrix job as `Windows-cl-release`, which is required. Two of the six
  rows are that case, so a per-job classification would have been wrong a third of
  the time on the very data it was derived from.
- **Not a job in `build.yml`**, because `check-release-gate` requires every job
  there to appear in `release.needs` and a notifier job is *skipped on a tag push,
  always* — which skips the release with it. That is the never-arrives failure
  aimed at the release, and it is why the clang-tidy job reports through a step.
  **Not a step in each unrequired job** either: a step sees only its own job, so
  it is ten copies of one decision, ten grants of `issues: write`, and it still
  cannot express the per-leg distinction above. So `workflow_run` — one workflow,
  every job's conclusion at once, running *after* the queue concluded, producing
  no status anything waits on.
- **`workflow_run` only ever runs the copy on the DEFAULT branch**, so nothing on
  a pull request exercises it and its first run anywhere is after it merges. The
  answer is the standing one: split the DECISION out
  (`scripts/ci-merge-group-report.sh`), drive it exhaustively against **captured
  real records** (`ctest -R merge-group-report-selftest`), keep acquisition thin,
  and assert the wiring statically (`ctest -R merge-group-report`).
- **The one claim that could not be measured is made self-revealing rather than
  quietly bet on.** That `workflow_run` fires for a run whose own event was
  `merge_group` is *reasoned* from GitHub's documentation, not measured, and it
  cannot be measured from a branch. So the trigger carries **no `branches:`
  filter**: the notifier fires on ordinary pull-request runs too and prints
  `event is 'pull_request', not merge_group`. From the first run after it merges,
  *it never fires* and *it fires and has nothing to say* are two visible states
  instead of one silence. A `gh-readonly-queue/**` filter would save a runner
  start and buy back exactly that ambiguity, so `check-merge-group-report` refuses
  one.
- The required-context list is READ out of `check-merge-queue-contexts.sh`. With
  an empty list every failure looks unrequired, so an empty read is refused rather
  than treated as *nothing is required*.
- **Neither the SET nor its COUNT is written in prose — this bullet is where that is
  recorded, and every other mention of it points here.** Every consumer reads
  `RequiredContexts`; the check prints `all <n> required contexts ...` on every run.
  Both were restated anyway, and promoting `clang-asan-ubsan` and `clang-tsan`
  ([#408](https://github.com/LASTRADA-Software/pace/issues/408),
  [#629](https://github.com/LASTRADA-Software/pace/issues/629)) meant editing all
  thirteen sites by hand with nothing to catch a miss: **eleven sentences across nine
  files** restating the count (`.github/workflows/build.yml`,
  `.github/workflows/merge-group-report.yml` twice, `scripts/ci-merge-group-report.sh`,
  `scripts/check-merge-queue-contexts.sh`'s own bash-3.2 guard comment,
  `src/tests/CMakeLists.txt`, `AGENT.md`, this file, `.agent/rules/testing.md`,
  `.agent/guides/team-run.md` twice), and **two more enumerating the whole set**
  (`build.yml`'s `changes` job and this file's own `paths-ignore` section). Eleven
  sentences in nine files, because two files carry it twice.

  **The first count of this said ten, and the miss is the interesting part.** The
  eleventh sentence was inside an anecdote about a past incident, so it was classified
  as a RECORD and left alone — and its verb was present tense: *"the required set **has**
  eleven members"*. A record of what was measured then and a claim about now are
  different things, and a paragraph can be the first while one of its sentences is the
  second. Sort by the VERB, not by the paragraph's subject.
  `git diff origin/master...HEAD | grep '^-' | grep -iE 'eleven|\b11\b'` returns eleven
  lines, one per sentence — but that is a count of LINES and agrees only because no
  sentence carries the word twice, so read it as corroboration and not as the census.
  One of the eleven sat **four lines below**
  `merge-group-report.yml`'s own header stating *a figure others will cite lives in ONE
  place they point at* — a file obeying a rule in one paragraph and breaking it in the
  next, which is how this shape survives review.

  **A stale LIST is worse than a stale count, and no count-shaped search finds one.**
  It reads as complete, so a leg checked against either enumeration would have been
  concluded *unrequired* rather than merely miscounted — and an enumeration carries no
  number, so the census that finds every restatement finds neither of them.

  **It is not guarded by a scan, and that is a decision rather than an omission.** The
  obvious guard — refuse a number adjacent to *required context* unless it matches
  `${#RequiredContexts[@]}` — was measured against the tree and matches six historical
  records that are not cardinality claims at all (*three required contexts came back
  `skipped`*, *five required contexts went green*, *ten required contexts went
  unwatched*, and #557's *ABSENT for all eleven*). Marking those as counts would
  misdescribe them, and narrowing the pattern to the cardinality phrasings means
  guessing at English determiners — which is [#495](https://github.com/LASTRADA-Software/pace/issues/495)'s
  and the `pgrep -f` lesson's warning that a pattern is broader than its author reads
  it. A guard whose false positives outnumber its true ones teaches people to work
  around it. [#830](https://github.com/LASTRADA-Software/pace/issues/830) carries
  the analysis; the enforcement here is that **the count is not written down**, so there
  is nothing for a scan to check.

**The SECOND door is a push to master, and it needed no new trigger**
([#774](https://github.com/LASTRADA-Software/pace/issues/774)). A job failing
there reaches nobody by the same mechanism: nothing gates a push, no pull request page
shows it, and the only trace is a run in the Actions tab that nothing points at — two
packaging jobs stayed red on master `dd4633b2` until a human went looking.

The `workflow_run` trigger was already unfiltered and already fired for those runs — the
decision script had always narrated *"event is 'push', not merge_group"* for them — so
the change is a ROW of `EventPolicy` and nothing else:

<!-- table-total: none -->
| event | policy | why |
|---|---|---|
| `merge_group` | report the **unrequired** failures | the required ones ejected the pull request and named the check |
| `push` to `master` | report **all** of them | nothing gates a push, so there is no already-surfaced set to subtract |
| `pull_request` | report **none** | the failure is on the pull request page, where somebody is already looking |

- `pull_request` is a ROW rather than an omission, so the decision to stay quiet is
  visible. A report per red pull-request job is noise, and noise is how a notifier gets
  muted.
- **The release gate did not change and should not.** `check-release-gate` already
  asserts every job in `build.yml` appears in `release.needs`, so a red packaging job
  cannot ship a release — it would fail again on the tag. What was missing is being
  TOLD, weeks before the tag rather than at it.
- **A push report is a TRANSITION; a queue report is an EVENT.**
  `PACE_REPORT_ONLY_IF_NEW` answers the ticket's own objection to reporting
  pushes: a context failing on every subsequent push would otherwise comment on one
  issue indefinitely and say nothing new. Per CALLER, never a default on
  `ci-report-issue.sh`, because the two callers genuinely differ and no default is right
  for both.
- **A push with no branch is REFUSED, never assumed to be master.** `build.yml`'s
  `push:` filter is `[master, fix-ci]`, and `fix-ci` is the branch CI experiments are
  expected to fail on. Defaulting an absent branch would report every one of them.
- Both of those are wiring the decision script cannot check about itself, so both are
  static assertions in `check-merge-group-report.sh` — and both were watched refusing by
  deleting the token from the real workflow. The policy itself is mutation-tested:
  giving `push` the queue's policy fails exactly the two cases written for it, and
  dropping the branch guard fails exactly the one.
- **A run nobody let FINISH is not a run that found nothing**, and that edge belongs to
  this change rather than to whoever meets it. Every job of a cancelled run concludes
  `cancelled`, which is `inert`, so the "nothing failed and nothing succeeded either"
  assertion refuses it — right about the RECORD and wrong about the tree, and cancelling
  a superseded run is ordinary. Before the `push` policy nothing read those records at
  all, so it could not fire; it is closed with the change that opened it. The RUN's own
  conclusion is the right question, not "were all its jobs cancelled": a run cancelled
  after some jobs finished carries a mix, and reading the mix reports the failures of a
  run nobody let finish.

### And the notifier then opened no report in its entire life (#1174)

`EVENT` was defined on the `decide` step's `env:` and read by the **reporting** step,
whose own `env:` never named it. A step's environment is its own — a sibling's `env:`
lends it nothing — so under `set -euo pipefail` the step died on its first line of real
work:

```
line 7: EVENT: unbound variable
##[error]Process completed with exit code 1.
```

Measured over the last 200 runs of the workflow at the time of the fix: **190 `success`,
10 `failure`, and all ten failures were that line.** The 190 are the `reportable == 0`
path, which never enters the step. So #684's notifier — the whole of the machinery above
— had never once opened a report, and #774's `push` half never had either. The contexts
it swallowed were real: `clang-tidy-windows` on a `pr-1153` queue attempt, `macOS-clang-release`
and `compile-cache E2E (Windows)` on `pr-1154`, `Code coverage` twice, and five more.

Three things had to be true at once for that to be quiet, which is #1031's shape
arriving in the instrument whose entire subject is failures nobody was told about:

- `-u` making the read an error rather than an empty string — the loud direction, and
  still invisible because nobody was watching this workflow's step-level results;
- the failing runs being **indistinguishable from the 190 healthy ones** in any listing
  that shows a conclusion per RUN. `gh run list` prints `failure` beside `success` in the
  same column for a workflow nobody has a reason to open;
- the workflow announcing itself exactly the way #774 says an unreported failure does —
  as a red run in the Actions tab that nothing points at.

**Why no rule caught it.** `check-merge-group-report.sh` asserts the shape of this
workflow and passed, correctly by its own rules. The rule that motivated the `$EVENT`
read is

```sh
grep -q 'PACE_REPORT_ONLY_IF_NEW' <<< "$(NonComment "$Workflow")"
```

a **whole-file** grep — and the line satisfying it is inside the step that cannot run. A
rule satisfied by a line that never executes is the same defect as a rule satisfied by
prose, which that file's own header records making twice. **So the rule is per STEP and
never whole-file; that is the whole of it.** `scripts/check-workflow-step-env.sh`
(`ctest -R workflow-step-env`) refuses a `run:` step reading a name that neither its own
`env:`, its job's or the workflow's `env:`, the script's own assignments, nor a named
allowlist of runner and shell variables supplies. A name an earlier step or an action
exported is not on that list: the step names it in its own `env:` (below).

It applies to **every** `run:`, not only the ones turning on `set -u`. Without `-u` an
undefined name expands to EMPTY and the branch is silently taken the wrong way, which is
the worse of the two failures and the one nothing would report.

Four things that shaped the guard rather than decorating it:

- The runner vocabulary is an **allowlist**, not a `GITHUB_*` pattern. An exclusion list
  bets on the world's layout; an inclusion list states your own — and a pattern broad
  enough to be convenient is what would have waved `EVENT` through.
- The model of bash is deliberately **narrow**. The first version took bare words off
  the front of any line as definitions, which made `echo`, `gh` and `api` variables —
  a model MORE PERMISSIVE than the shell, in a check whose entire purpose is that a
  permissive model waves through the one read that matters. Only a declarator
  (`export`/`readonly`/`local`/`declare`/`typeset`) names several; anything else names
  at most one, and only with an `=`.
- The refusal names the **step**. A guard's remedy text is part of the guard, and one
  saying `(unnamed)` cannot be acted on — which is what the first version printed,
  because a steps list item carries its first key on the dash line and the parser
  consumed the whole line as a boundary. That same bug read `- env:` as declaring no
  environment at all, so the check's own fixture passed for the wrong reason.
- The self-test's `correct` fixture **modelled the defect**: it emitted a reporter step
  reading `$EVENT` with no `env:` at all, and called that the correct workflow. A
  fixture more permissive than the thing it stands for, vouching for the bug it was
  built beside. Its `no-event-env` sibling became the positive control, and every
  whole-file rule still passed on that fixture — which is precisely how the shipped
  workflow passed them for its entire life, so a green run of the other twelve cases
  said nothing about this one. It lives on as `siblingStepEnv` in the step-env check's
  self-test, beside the rule it controls.

The scan was **one workflow's** for its first life, inside `check-merge-group-report.sh`:
exact about the three steps it knew and silent about the rest of the tree's `run:` steps,
which reads identically to complete coverage. It walks every workflow file as a glob now
(#1448, #1175), and generalising it was not a wider glob but a MODEL of each shell:

- The shell is DERIVED per step — its `shell:`, the job's or workflow's
  `defaults.run.shell`, else the runner default of `runs-on` in EVERY combination of the
  job's matrix, which must agree (#1432: `varying-shell` otherwise) — and a step
  whose shell cannot be derived, or has no model, is refused. Run over `build.yml` at
  fa8fb0c3, the one-workflow model refused 13 PowerShell steps for `$LASTEXITCODE` and
  `$null`, and 4 bash steps for `{ c=$?; }`, all falsely; PowerShell reads the
  environment only as `$env:NAME`, case-insensitively.
- Job-level `env:` reaches that job's steps only. The first model kept one file-wide set,
  harmless over a one-job file and too permissive over `build.yml`.
- A folded `run: >` is a run. The first model never read one, silently.
- A name an earlier step or an action EXPORTED reaches a later step at run time and is
  still refused until the step names it — `NAME: ${{ env.NAME }}`, which the tree already
  wrote for `CLANG_TIDY_BIN`. Modelling every `$GITHUB_ENV` spelling and every action's
  exports would be a row per action; the row says where the name comes from, in the step.
- The reader refuses a line it cannot place — a flow mapping, an alias, a quoted key, a
  second document — rather than skipping it, and a clean run is shown able to fail on the
  REAL files: `workflow-step-env-plant` appends a read of an undefined name to the end of
  every step, through the same lexer, and passes only when every step refuses it.
- **The plant cannot see a step the reader never placed**, and nor can anything else the
  reader computes: a step whose keys sit at a column it does not look at reads as a step
  reading nothing, which is clean. So every `run:` key outside a scalar is COUNTED by a
  second walk that knows no steps, both numbers are printed per file, and a key the reader
  did not place is refused by line. Its positive control is on the real tree: the
  `- run: ${RUN_URL}` lines inside `merge-group-report.yml`'s heredocs are text, not keys.
- A tracked composite action has `run:` steps under the same rule and none is read, so one
  is refused by NAME rather than left outside a pass that reads as complete. The file set
  is `git ls-files -z`: a plain listing QUOTES a path holding a byte outside ASCII, and
  `*/action.yml` then misses it.
- **A definition is a LINE** (#1461). The first model counted a name as defined by a step if
  the step assigned it ANYWHERE, so `echo "$X"` above `X=1` passed — a model LOOSER than
  bash, in the check whose whole purpose is that a loose model waves through the one read
  that matters. A read is judged against what is defined at or above its own line, loosened
  to the whole script inside a LOOP body, which runs again, and a FUNCTION body, which runs
  wherever it is called. **Losing the construct is a REFUSAL** (`unreadable-construct`), not
  a fall back to judging the script as if it had none: a reader that cannot say where a loop
  ends cannot say which reads are ordered, and the looser answer is the silent one.
- **And `trap`, the third shape the ticket named, needs NO relaxation — that is a finding,
  not an omission.** A single-quoted handler is not expanded at all, so the lexer has
  already masked its `$` and no read is seen in it; a double-quoted one is expanded WHERE
  `trap` IS CALLED, so ordering is already the right answer there. Writing the relaxation
  anyway would have added an arm that could never fire, and nothing would ever have said it
  had stopped working. What the pair of cases pins instead is the DISCRIMINATION: single
  quotes accepted, double quotes refused. Neutering the mask reddens the single-quote case
  along with four pre-existing ones, which is what says the answer rests on the lexer.
- **And the `${{ env.NAME }}` expressions are read too** (#1460). The convention this check
  established -- bring an exported name into a step as `NAME: ${{ env.NAME }}` -- concentrates
  the risk in one spelling: an expression naming nothing in scope is substituted with an EMPTY
  string, with no error, so a typo defines the name the shell half then finds and nothing
  objects. Read in a step's `run:`, `with:`, `if:`, `name:` and `env:` values; satisfied by the
  workflow's or the job's `env:`, an EARLIER step's `$GITHUB_ENV` write, an `ActionExports`
  row, and -- for every field except a step's own `env:` VALUES -- the step's own `env:`.
- **That exception is the whole rule and not a detail**: GitHub substitutes an `env:` value
  before the step's environment exists, so `SCCACHE_PAHT: ${{ env.SCCACHE_PAHT }}` would
  otherwise satisfy ITSELF -- the one shape the ticket was opened for. A step cannot read what
  it exports or writes either, for the same reason one step along, and the two cases that say
  so exist because a NEUTER showed the obvious ones could not: they put the read in one step
  and the source in another, so they discriminate WHICH STEP and never WHEN IN THE STEP.
  Neutering the order reddened nothing. **A case that cannot fail for its stated reason is the
  default outcome, not bad luck.**
- Two limits are pinned as PASSING cases rather than left to be rediscovered: the grain is a
  LINE, so a read and an assignment on ONE line are not ordered against each other
  (`for x in a; do echo "$X"; X=1; done` is accepted), and for PowerShell the relaxation is
  every brace-enclosed block, because its loops, its functions and its `if` blocks are all
  brace-delimited. Delete either case and the limit stops being a decision. No pwsh step in
  this tree assigns an environment name at all — `$env:NAME =` appears nowhere under
  `.github/workflows` — so that half is carried by the cases and by nothing else.

What it cannot see is stated in its own header.

**And it is no longer the only reader: there is ONE model of workflow YAML, and it is
`scripts/lib/workflow-walk.awk`** ([#1456](https://github.com/LASTRADA-Software/pace/issues/1456)).

Five checks each carried their own awk walk over `.github/workflows`, and four of the five spelled
`build.yml`'s two-space indentation as literal column counts -- `/^  [A-Za-z0-9_-]+:/`, `/^    if:/`,
`/^      - /`, `/^        run:/`, `/^          key:/`. **Every one was right about the file and wrong
about YAML**, written by somebody who had the file open. The reader above was the exception, the only
depth-relative one, and the only one whose self-test drove folded scalars and heredocs -- so the walk
was extracted from it, and its output over the real files is byte-for-byte unchanged.

- **The library calls exactly ONE hook, `WorkflowOn(kind)`, and that is measured rather than
  chosen.** gawk makes a call to an undefined function FATAL, so a consumer that forgets the hook
  cannot report clean -- it cannot run at all. But the error names an `FNR`, and **the enforcement
  is per reached PATH, not per program**: a hook called only on some lines exits 0 in silence until
  such a line appears, and is then a fatal error in CI on somebody's unrelated pull request, naming
  an awk function rather than the check that lacks it. Eight hooks would have been seven of those
  waiting. The `raw` kind fires on every line of every input, so the one hook is reached before
  anything else can be.
- **A kind with no arm falls off the dispatcher and returns**, so every consumer spells a returning
  arm for every kind including the ones it ignores: *a kind nobody decided about and a kind decided
  to be uninteresting are otherwise the same silence.* Adding a kind to the library is therefore
  adding an arm to all five consumers, and that is the price the one-hook design pays for being
  able to add a kind at all.
- **The same defect was already in the tree, in the library extracted one increment earlier.**
  `scripts/lib/shell-lex.awk` called a `trim` it does not define, which lives in one consumer: a
  second consumer would have died at its first heredoc, fatally, and only once a heredoc appeared.
  A library defines every function it calls, and nothing but a second consumer would have said so.
- **Three defects the walk shipped with were found by READING A TRANSCRIPT, not by review**, and
  none was visible to the one consumer it had: a job flushed only after the NEXT job's key event,
  so a consumer reading `WfJob` on the line `  second:` was told `first`; a pass whose LAST job was
  never flushed, because `END` runs once and a new file only resets; and `WfPath` under a refused
  line inheriting the ancestry of whatever key last sat at that indent. Dumping the records for a
  rich fixture and reading them is a different activity from reviewing a diff, and it is the one
  that finds this class.
- **A neuter is evidence only over input that REACHES the line it disabled.** The walker's
  self-test reports a neuter that provoked nothing as its own failure, and did so three times: a
  fixture reaching two of four block-opening shapes, a `WfBlockKey` assignment already made by the
  branch above it, and a folded `if:` the shipped fragment writes on one line. Each time the hole
  was in the FIXTURE, and each time a green run would have read as coverage.
- **A SET cannot see a value attributed to the wrong key when that key owns others too.** The
  walker's driver counts continuations per owner for that reason: neutering the `run:` site moves
  `run` from 3 to 2 and adds `name=1`, a body line attributed to the step's own `name:`. As a set
  of owners, `run` was present either way and the neuter looked inert.
- **Migrating a reader is not enough, and a green self-test afterwards says nothing about WHERE the
  reading came from** -- every existing case passes just as well over a private reader kept beside
  the shared one. So each migration neuters the LIBRARY and requires the check to refuse, with an
  untouched copy at a different path as the control.
- **That neuter found a hole in `check-gated-jobs.sh` that the migration did not introduce**: with
  a reader placing no job, four of its six rules answer "nothing to vouch for" and it passes. Its
  rule C even emitted rows with an empty job column while its own *no step runs the doc checks*
  refusal stayed silent, because the string was not empty. *Absence of the negative is not the
  positive*, so it asks for a POSITIVE CONTROL first -- how many jobs the walk placed -- and
  refuses on zero.
- **`ctest -R workflow-walk-sole` is what stops the sixth private walk**, because the migrations
  cannot: `/^  [A-Za-z0-9_-]+:/` is four characters and works on the file in front of you. It
  refuses an awk regex anchored on a FIXED indent in a first-party script that names a workflow,
  passes a depth-relative one, and exempts a fixture GENERATOR by row with a reason -- a stale row
  is refused, because an exemption kept past its subject excuses whatever next takes that path.
  What it cannot see is in its header: an indent built at run time (`awk -v job="  $2:"` was one of
  the spellings removed here), a `substr($0, 1, 4)`, an `index($0, "    if:")`.
- **The two libraries are separate, and one consumer proves it**: `check-merge-queue-contexts.sh`
  loads the walk and not the lexer, because it reads no shell. Merging them would have made every
  YAML reader carry a bash model it has no use for.
- **A job MATRIX is the walk's too, and three private partial models of one is the same defect as
  five private walks** ([#1432](https://github.com/LASTRADA-Software/pace/issues/1432)). One
  check expanded `${{ matrix.preset }}` over a `preset:` flow list and nothing else, one mapped
  `runs-on` to an OS only when it was literal, one refused any expression in `runs-on`. So the first
  matrix to grow a `runner:` axis, adding an arm64 leg as a ROW so the required context names do not
  move, failed all three, each on its own misreading. The walk now turns `strategy.matrix` into
  combinations with GitHub's semantics: the cartesian product of the axes, less every `exclude`,
  then each `include` row merged into every BASE combination whose ORIGINAL values it overwrites
  none of, else added as a combination of its own. A key a combination lacks expands EMPTY, as
  GitHub does, which is what keeps the x86 legs' names where they were. **Both arms of the include
  rule are the load-bearing part**: a row overwriting an original value is a NEW leg (#1432's
  `runner:` row), and a row matching one, or naming no axis at all, MERGES. The fixture that pins
  it is GitHub's own documented example, the one expected answer not written by the model's author.
- **A matrix the walk cannot read is a REFUSAL (`unreadable-matrix`) and leaves NO combinations,
  never one plausible leg**: an expression in its place, a row that is not a block mapping of plain
  scalars, a value carrying an expression, an exclude naming no axis -- and a plain value YAML TYPES
  as anything but a string, an integer or `true`/`false`, since `3.10` is the number 3.1 and that
  is what GitHub renders. A reference differing from a key only in CASE is left unexpanded for the
  consumer to refuse rather than expanded empty. Each consumer then asks per combination: a
  context per leg (a matrix job whose name carries NO expression is refused, because GitHub
  decorates it with the leg's values), a shell per leg's runner, a cache writer per leg.
- **A cache key the legs do not vary is one key written by every leg at once** -- legs run
  concurrently exactly as jobs do, so that is #318 arriving through a matrix, and rule F refuses it.
  The first patch for #1432 was refused for exactly that on its CPM key.
- **So a leg is a writer of a step UNLESS the step's `if:` decidedly rules it out**
  ([#1540](https://github.com/LASTRADA-Software/pace/issues/1540)), which is what makes the
  shape IDENTICAL content wants expressible: `actions/cache/restore` on every leg and
  `actions/cache/save` guarded by `matrix.suffix == ''`, as the `linux` job's CPM steps are. **The
  rule is one writer per KEY, never one per job**: each preset has its own key, so a guard picking
  one leg of the job would leave every other preset's key with no writer at all -- `matrix.suffix ==
  ''` gives each key its x86 leg and leaves the arm64 legs only restoring. The walk decides a
  condition from the leg's matrix values alone (`WorkflowMatrixDecide`: `==`, `!=`, `!`, `&&`,
  `||`, parentheses, string literals, GitHub's case-folding and null coercion), in THREE-valued
  logic, and **UNDECIDED is never read as false**: a `steps.*`, `needs.*` or function term leaves
  the leg a writer, so an `if:` it cannot read keeps the refusal it had -- a staged neuter reading
  undecided as "does not run" is what shows the refusal rests on that. A save key taken from
  `cache-primary-key` is refused as unresolvable, since each leg computes it; spell the key as the
  restore step does.
- **Ruling legs out opened the other direction, so rule F refuses NONE as well as TWO**: a key an
  `actions/cache/restore` step reads that no step any leg can run writes. Two writers cost an
  upload; none costs the cache in silence -- every run misses, a `restore-keys` prefix at best hands
  back an entry saved for a different key, and the job reads as cached. The refusal names the key
  and the restoring legs. Only `key:` is compared: a `restore-keys` prefix is not a key, so it
  neither needs a writer nor supplies one -- the self-test gives the restore step a prefix of the
  key that IS written, and the unwritten one is still refused. While any writer's key could not be
  resolved the answer is UNDECIDED and says so, never "nothing writes it".
- **One key is not one entry**: GitHub finds an entry by key AND a version hashed from `path:` as
  the runner EXPANDED it plus the compression the tool chose (`getCacheVersion`, reproduced
  exactly against this repository's Linux, Windows and macOS CPM entries). `windows-2025` and
  `windows-11-arm` disagree on both -- `D:\a\...` against `C:\a\...`, and zstd is on the first and
  in the second image's list of OMITTED software -- so the `windows` job's legs keep a key each.
  Rule F compares key TEXT, so over such legs it passes a restore whose only writer is the other
  runner (a false GREEN) and refuses two such writers that write two entries (a false red, whose
  remedy is what they need anyway); `build.yml` says at each shared key what is known of it.


**A Windows leg that cannot start processes reports six red smoke tests, not a
runner fault** ([#966](https://github.com/LASTRADA-Software/pace/issues/966)).
Observed on `Windows-cl-debug`: six failures, all exit `0xc0000142`
(`STATUS_DLL_INIT_FAILED`), and they were exactly the six tests that spawn a process
while every in-process case in the same binary passed.

No defect in the tree selects for "spawns a process" — a broken link, a missing
runtime or a bad DLL would take the in-process cases with it. But nothing said so, and
six red smoke tests read as a regression. That matters most on this leg specifically:
it is the one run for `_ITERATOR_DEBUG_LEVEL=2`, so its smoke tests are where a
Debug-runtime defect surfaces, and a leg that intermittently reports nothing about the
property it exists for is worse than one that is simply red.

So `ctest` is BRACKETED by a spawn probe, and the PAIR is what carries the meaning:

<!-- table-total: none -->
| before | after | what it means |
|---|---|---|
| red | — | the runner was broken on arrival; nothing after it is about the tree |
| green | green | not #966's shape — and that is ALL it says (#1515, below) |
| green | red | the runner degraded DURING the run — #966 exactly |

- The probe is `cmd /c exit 0`: it starts a process and does nothing else, so it
  cannot redden a green run for any reason but the one it names.
- The "after" half runs only on a red and is `continue-on-error`: a classifier on an
  already-failing job must be able to explain the verdict and never to change it.
- It has **three** outcomes, not two — broken, working, and *could not conclude* —
  because a probe that can only answer the two you expect will answer one of them
  whatever it sees. And it says out loud that it is a reading taken after the fact.

**A probe of one capability cannot clear a runner that degraded in another**
([#1515](https://github.com/LASTRADA-Software/pace/issues/1515)). The green/green
row used to read *"read the failures as being about the tree"*, and the step printed
exactly that over one red: `mkdocs-validation`, measured at 170 ms, `***Timeout` at
60.34 s on a branch whose inputs were disjoint from it. The runner could still spawn,
so the probe was right about what it tested and wrong about what it licensed — and it
licensed it in the direction that gets acted on, since a red on a required context
already reads as *my branch is bad*.

So the verdict moved to `scripts/ci-ctest-red-reading.sh`, which reads the spawn
reading **and** the log `ctest --output-log` wrote:

- **A timeout never reaches the tree verdict.** A hang in the tree and a runner that
  stopped making progress both end in one, and nothing in the log separates them; the
  timed-out tests are named and the reader is sent to their cost on a green run of the
  same leg. `TIMEOUT` is not raised: a sub-second check that did not finish in 60 s did
  not run out of budget.
- **`--output-log`, because nothing else carries the distinction.** `LastTest.log`
  writes `Test Failed.` for a timeout and a failed assertion alike; only the console
  and `--output-log` say `***Timeout` and `N - name (Timeout)`.
- **The FAILED list is checked against ctest's own count** before a missing
  `(Timeout)` row is believed, and no log, no summary and a short list are three named
  unclassified warnings rather than one fall-through.
- **Both wiring mistakes fail toward unclassified, never toward the tree**: a log path
  that disagrees with the `Test` step's is `no-log`, and a misspelt step id substitutes
  an EMPTY spawn reading, which is not `ok`. `ctest -R ctest-red-reading-selftest`
  drives every verdict and asserts only `tree` tells a reader to blame the tree.

### Doc-subject checks were skipped on doc-only changes (#687)

`ci-scope.sh` answers `code=false` for a `docs/**`, `.agent/**` or `*.md` change
and every heavy job is gated on it — right for a compiler, and backwards for the
handful of checks whose SUBJECT is prose. **Prose drifts by being edited, so a
prose-only edit is precisely the change those checks never saw.** Both live
findings #462 fixed came from doc-side hand edits.

Reproduced end to end on one commit: a four-line addition to `docs/how-it-works.md`
recommending the sccache-over-pace setup — naming one of the two backend
environment variables `check-sccache-backend-caveat.cmake` scans for — with no
caveat after it. `ci-scope.sh` classifies that commit `code=false`, so on master
today no `ctest` runs at all; `doc-subject-checks.sh` on the same tree exits **1**
and names `sccache-backend-caveat`.

**And then the same guard caught this very paragraph.** Written with the variable
spelled out, it *was* a page naming the marker with no caveat within forty lines,
so `ctest -L hygiene` went red on an edit that touched only `.agent/**` and
`AGENT.md` — which is the ticket's whole thesis arriving unprompted, in the commit
that fixes it, on the one class of change that used to run no check at all. The
fix is to describe the marker rather than spell it: this paragraph reports a
reproduction, it does not recommend a configuration, and `check-sccache-backend-caveat.cmake`
cannot tell those apart from a text scan — which is exactly why its exemption
table takes a per-row reason. Adding a row for the rulebook would have been the
wrong move: the caveat rule is right and the prose was wrong.

- **Reporting is not gating, and this needs the second.** A doc check in an
  unrequired job is #684 one file over. So the step lives in `check-clang-format`
  — whose `name:` is the required context `Check C++ style` — restructured to the
  shape `linux`/`windows`/`macos` already use: job-level `if: ${{ !cancelled() }}`,
  the scope gate moved onto the clang-format steps, the doc-subject step ungated.
  What changes for a docs-only pull request is that this context now reports
  success or FAILURE where it used to report `skipped`, and a skipped required
  context is read as passing. The `name:` is a wire constant; renaming it renames
  a required context.
- **No new job**, for `check-release-gate`'s reason above.
- **A check that reads BOTH SIDES is the answer when a diagnostic is unreachable
  by unit test.** `docs/operations/corrupt-store.md` quotes startup diagnostics
  verbatim and exactly one of them was asserted anywhere (#633) — because the
  daemon's `StorageOpenFailure` sits in an ANONYMOUS NAMESPACE in `main.cpp`,
  behind `add_executable(pace-kv main.cpp)` with no test target, and the node's
  sentence is composed in a third file in a different binary. Asserting them by
  unit test needs the app restructured; a `docs-subject` check reading the page
  AND the composing sources needs no linkage at all, and covers both binaries.
  The page's usefulness *is* that an operator recognises their own console output
  in it, so the thing to pin is that the source can still compose what the page
  shows.
  - **Assert PRESENCE in the composing source, never equality with a formatted
    line** — the latter is a change-detector that fails on every wording tweak,
    which is what #633 exists to avoid. The shard sentence's field-level
    assertion is the `'{}'` that carries the path.
  - **The exception proves it rather than breaking it**: for the
    `StorageError(code={} system={} context={})` rendering the WHOLE format string
    is pinned, because that rendering *is* the verbatim quote. A change-detector
    is exactly right where the literal is what moved onto the page.
  - **A sentence composed in three places needs a per-FRAGMENT table, not a
    per-sentence one.** The node's refusal is `--cache-dir {}` and
    `cannot open {}` in `CacheTier.cpp` plus `refusing to start` in its own
    `main.cpp`; a check reading only the tier misses the suffix and reports clean.
  - And the set is derived from the PAGE, so **a quoted diagnostic no row covers
    is REFUSED**, never passed over. An uncovered quote is precisely the silent
    gap the check exists to close, and a table that quietly ignores one is the
    check vouching for something it never read.
- **The set is the `docs-subject` ctest LABEL**, read out of
  `src/tests/CMakeLists.txt` along with each check's `-D` arguments, its
  `SKIP_REGULAR_EXPRESSION` and the one `PACE_SCRIPT_CHECK_FAILED` spelling.
  Nothing is restated, so a check that grows an argument cannot silently start
  running with the wrong one.
- **Every way of not being able to run is a REFUSAL, never a skip**: a label
  matching nothing (#687's own acceptance clause), a command still holding a
  build-tree variable, a missing script, a missing fail-regex, and a run in which
  every check skipped. That last one is *absence of the negative is not the
  positive* — nothing failed because nothing ran.
  It has been watched refuse on the real tree: `sccache-backend-caveat` was
  labelled while `-DPACE_SCAN_BUDGET_SECONDS=${PaceSccacheCaveatBudgetSeconds}`
  could not be resolved, and it was named rather than skipped. Resolving
  file-local `set()` variables is what fixed it, and it keeps that budget one
  value serving both the argument and the ctest `TIMEOUT`.
- **`compile-cache-caveat` is deliberately NOT labelled** and the gap is stated:
  it takes five build-tree facts and configures a throwaway project (600 s
  timeout). The refusal above is what stops somebody closing the gap by labelling
  it and getting a silent skip.
- `ctest -R gated-jobs-fail-safe` gained a third rule over both halves — the step
  is ungated, and its job produces a required context — and, for the first time,
  a `--self-test` that drives all three rules against generated workflows. They
  had only ever been seen to pass.

### Seven ways an instrument reported on something other than its subject

Every one of these was written by somebody who had just read this file, and every
one produced a green or a red that was about the tool rather than the tree. They
are recorded together because the shape is one shape.

- **A COMMENT is not a call site — twice, in two different checks.**
  `check-gated-jobs.sh` matched its own explanatory comment naming
  `doc-subject-checks.sh` and attributed it to whichever step block was open,
  reporting the same step twice; `check-merge-group-report.sh`'s header explains
  that it refuses `always()` and `cancel-in-progress`, and both rules fired
  against a correct workflow. **A rule satisfied — or refused — by prose is a rule
  that passes with the code deleted.** Strip full-line comments (`^[[:space:]]*#`)
  and never a trailing `#`, which in YAML needs preceding whitespace to start a
  comment. Both directions are self-tested: the baseline workflow deliberately
  carries a comment naming every forbidden spelling, and a second baseline carries
  no comments at all.
- **`bash <path>`, never a bare path — in a self-test AND in a workflow, and the
  file mode is not the whole reason.** It fired twice in one branch, in the two
  places whose failures look nothing alike.

  In a self-test, `check-gated-jobs.sh --self-test` re-invoked itself as a bare
  `"$0"`. These check scripts were mode **644** — ctest runs them as `bash <path>`
  and nothing needed the executable bit — so it exited **126, Permission denied**,
  having run no check at all, and every `want-fail` case passed because the SHELL
  refused rather than because the rule fired: **eight cases, entirely green,
  testing nothing.** Caught by the one case that expects a PASS, which is the
  argument for a baseline case rather than only negative ones.
  [#720](https://github.com/LASTRADA-Software/pace/issues/720) is the mode
  across fourteen scripts;
  [#723](https://github.com/LASTRADA-Software/pace/issues/723) is the rule
  that survives a chmod.

  **The mode half is CLOSED and the past tense above is deliberate.** `ctest -R
  script-modes` requires every tracked shell script carrying a shebang to be
  `100755`, so the 126 described here cannot happen in this tree today. Six
  comments and one `AGENT.md` bullet went on asserting the present tense long
  after #720 repaired it, and a manager briefed five lanes from one of them
  before a lane checked it against `git ls-files -s`
  ([#1033](https://github.com/LASTRADA-Software/pace/issues/1033)). No
  corrected COUNT replaces them: the property is enforced, so a figure would be a
  second source of truth for a fact a check already owns. Do not restate the
  ratio; run the check. What survives untouched is the rule — a call that fails
  to START fails for reasons a chmod does not cover, and inside a `want-fail`
  assertion any of them is indistinguishable from the rule firing. **A false
  concrete reason discredits a true rule**, which is why the reason was corrected
  rather than the practice dropped with it.

  In a workflow it is louder and reaches further. `build.yml`'s new doc-subject
  step shipped as a bare `run: scripts/doc-subject-checks.sh` and CI reported
  **`Check C++ style` — a REQUIRED context — as FAILED**, on step 3 of 5 with both
  clang-format steps skipped behind it. Reproduced locally against the same mode
  and the same invocation: exit **126**. It was found by reading `git ls-files -s`
  against the call site before the run finished, not by the run — which is the
  only way to find it, since a local run types `bash` in front of the script by
  habit and can never reproduce it.

  **The mode is the smaller half.** Both scripts are 755 now, so the bare form
  would work — and every call site names its interpreter anyway, because a call
  that fails to START fails for reasons a chmod does not cover: a moved file, a
  `noexec` mount, a lost mode bit. Inside a `want-fail` assertion any of those is
  indistinguishable from the rule firing, which is the eight-green-cases failure
  again with a different cause. Name the interpreter regardless.
- **`IFS=$'\t' read -r a b c d` does not read tab-separated fields.** Tab is one
  of bash's three IFS *whitespace* characters, so a run of tabs collapses to one
  delimiter and leading ones are dropped — a record with an empty field silently
  SHIFTS every field after it. The empty field is exactly the case that matters
  here, since `gh` renders an unfinished job's conclusion as the empty string.
  Split by hand (`${line%%$'\t'*}`) and count the delimiters first.
- **A fixture built on `message(FATAL_ERROR)` cannot test the rule that verdicts
  are read from OUTPUT.** It exits **1**, so the exit status alone is sufficient
  and deleting the output half of the verdict left the self-test GREEN. The mode
  under test was not the mode in use. There is now a fixture per arm: one that
  prints the failure text and exits 0, one that exits non-zero with clean output.

  This bullet said the exit code was **0** on 3.28 and **1** on 4.3, which made
  the defect sound like a property of the reviewer's host. It is not — the exit is
  1 on every version measured (#565) — and the correction makes the finding
  **stronger**, not weaker: the fixture was insufficient on every machine, always,
  rather than only on a modern one. It is left recorded because a wrong premise
  under a right conclusion is the hardest kind to notice, and this bullet is the
  same defect as the section above it, one level down.

- **CMake WRAPS its diagnostic messages, so a phrase you grep for may exist in the
  output and in no single LINE of it.** A mutation harness reported all three of its
  arms as `SELFTEST STAYED GREEN -- this mutation is NOT covered` while the self-test
  was in fact RED with four cases named. The phrase it matched on,
  `did not behave as claimed`, straddled the wrap point. Measured:

  <!-- table-total: none -->
  | message type | matches for a phrase crossing column 74 |
  |---|---|
  | `message(STATUS)` | **1** — does not wrap |
  | `message(WARNING)` | **0** |
  | `message(FATAL_ERROR)` | **0** |
  | any of them, whitespace flattened first | **1** |

  **The `STATUS` row is the trap inside the trap, and there are TWO ways to write the
  negative test wrong.** It does not wrap, so a test written with `STATUS` reproduces
  nothing and reads as a refutation of the whole claim; and in a file emitting BOTH, the
  unwrapped `STATUS` copy satisfies the grep and masks the wrapped one — which is what
  the first attempt here did, returning 1 match. Both failure modes read as a
  refutation, so a reader who tests only the first still concludes the rule is false.
  Same structure as *a green probe of the wrong shape is not a refutation*, in a
  different tool.

  **And this is a property of every verdict this repository reads, not a trap somebody
  might hit.** A `cmake -P` check's verdict travels through the DIAGNOSTIC channel by
  construction — its registration is read by `FAIL_REGULAR_EXPRESSION`, which must also
  hear a check that merely WARNS, and `message(WARNING)` exits 0 on every CMake. (This
  said *"`message(FATAL_ERROR)` prints and exits 0 on 3.28"*; that does not reproduce —
  exit **1** on 3.22.6 through 4.3.0, #565 — and the conclusion never needed it, since
  what makes the channel load-bearing is the warning half, not the exit code.)

  Measured: **37 of 37** `scripts/check-*.cmake` carry `message(FATAL_ERROR)` — on the
  branch that added this entry; **35 of 35** on the master it branched from, the two
  extra being that change's own; and **43 of 44** after #565 landed beside it. Every
  figure is right for the tree it was taken on, which is the census rule arriving a
  third time: not a different pattern here, the *same* pattern on a different tree.
  State which tree, or the next person measures 35 and concludes the rule overstates
  itself.

  **And the 44th is the one to read.** `scripts/check-fatal-error-exit-selftest.cmake`
  carries no `message(FATAL_ERROR)` at all — it reports through `message("CMake Error:
  …")`, which is what several checks here already do. So the census was a PROXY for
  "reports through the diagnostic channel" and the proxy has now parted company with the
  property: the conclusion above still holds for all 44, and the count that stood in for
  it does not. A census whose pattern is a proxy states which one it measured.
  Every one of them is a check whose verdict cannot be read by a substring match that
  crosses column 74. So flatten (`tr '\n' ' ' | tr -s ' '`)
  before matching any verdict text, or match a phrase short enough that it cannot
  straddle the wrap.

  This is not any of the six above. Those are wrong buckets, wrong populations, a
  substring of a count, a comment matching itself. **This one is: the text you are
  matching does not exist in the form you are matching it in, and the tool that
  printed it is what changed the form.** The subject was fine and the reading was
  fabricated by the formatter in between.

  The tell is the one worth keeping: **three arms agreeing perfectly is what a broken
  instrument looks like as well as what a real pattern looks like.** Refusing "all
  three uncovered" and printing the raw output is what found it — the same move as
  treating two legs disagreeing at 3220/3216 as evidence about the instrument rather
  than about the tree.
- **A self-test that stops early must not look like one that judged something.**
  A generator ending in `[[ ... ]] && echo` returns 1 when the condition is false;
  under `set -e` a plain call to it took the whole self-test down after eight
  cases — exit 1, no case named, indistinguishable from a real failure. The
  self-tests now print the number of cases they ran, so a truncated run is
  visibly truncated. The count is printed rather than compared against a number
  restated in the file: a second copy of the expected total is a second thing to
  be wrong.

### A counterfactual must fail through the rule, not merely fail

Its own section rather than a sixth bullet above, and the reason is the section
above's own heading: those are **six ways in ONE branch**, written by people who
had just read this file. This one is from a different branch and a different
ticket, so filing it there would have made a counted, scoped claim false --
silently, because the heading sits outside any diff window that shows the
insertion. A clean textual merge cannot see that, which is the same failure this
file records against the store lane's insert.

**A counterfactual must fail THROUGH the rule, not merely fail — and a deletion
is the easiest one to write and the likeliest to be invalid.** Removing the branch
under test is the obvious way to show a guard bites, and it changes two things at
once: the behaviour, and whether the tree still compiles. `SecretCameFromConfigFile`'s
provenance branch WAS the whole use of its `cli` parameter — #752 moved the rule onto a
`SecretProvenanceFacts` both executables build, and #753 then deleted the
`(Config, CliResult)` adapter that was left, so the signature named here no longer
exists — and deleting the branch left the parameter unused, `-Werror` refused the
build, and the arm went red for a COMPILATION reason while claiming to demonstrate
the rule
([#384](https://github.com/LASTRADA-Software/pace/issues/384)). Nothing in the
red output says which of the two it was.

**This is the mirror of the `want-fail`-satisfied-by-exit-126 rule above**, and both
polarities are now on record: there an arm PASSED for the wrong reason (the shell
refused to start the script), here an arm FAILED for the wrong reason. One missing
state underneath both — a run that did not happen is neither a pass nor a failure —
which is why the harness that caught this one is the harness that reports
**INCONCLUSIVE** rather than scoring a build failure as red
([#747](https://github.com/LASTRADA-Software/pace/issues/747) is that state
generally; this is it existing in one script and earning its keep).

So a counterfactual is a **plausible WEAKENING** rather than an amputation: for the
provenance gate, one that still consults the bit and only excuses an already-empty
secret — a mistake somebody would actually make, which compiles, and which can fail
only through the rule. Where an amputation genuinely is the right shape, the harness
has to be able to say the build broke; a script that reports "red" for both is an
instrument that cannot tell you what it measured.

### An insert is judged by what its CONTAINER claims, not by its neighbours

**Adjacency is not the test, and checking it is not enough.** A rule inserted into
this file was read against both junctions -- the paragraph above it, which it
explicitly references, and the one below, which is independent. Both read
correctly. The insert was still wrong, because the sentence it falsified was
**neither neighbour**: it was the heading of the section it had joined,
*"Six ways an instrument reported on something other than its subject, in one
branch"*.

Two claims broken at once, and they are different KINDS of claim:

- **A count.** "Six ways" is arithmetic over the section's members. A new member
  changes it.
- **A scope.** "in one branch", and the opening *"Every one of these was written by
  somebody who had just read this file"*. The inserted rule came from
  [#384](https://github.com/LASTRADA-Software/pace/issues/384) -- a different
  branch, a different ticket -- so it was never one of "these", however well it fit
  the theme.

Neither sentence is anywhere near the hunk. **No diff shows it and no merge
algorithm can**: `git` reported a clean rebase, correctly, because the hunks were
disjoint. Disjoint hunks are a statement about text, and a document makes claims
about its own structure that text adjacency cannot see. This is the store lane's
"a clean textual merge can still leave a neighbouring sentence false", one level
out: not the neighbouring sentence, the ENCLOSING one.

So the question to ask of an insert is not *"do the adjacent paragraphs still
read"* but:

> **What does the enclosing structure claim about its members, and is my member one
> of them?**

The shapes that make that question bite are worth naming, because they are easy to
read past: a **counted heading** ("Six ways", "The three doors above"), a **scoped
intro** ("in one branch", "all found together", "every one of these"), a
**demonstrative** ("these two are the same disease"), and a **back-reference** from
a later section that counts what came before. Where the answer is "my member is not
one of them", the fix is a section of its own rather than a smaller edit to the
claim -- the claim is usually load-bearing prose somebody measured.

**The person who produced this defect was the person enforcing the rule on other
lanes that same day**, and had checked the junctions deliberately rather than
skipping the check. That is the evidence, and it is why this is a rule rather than
an anecdote: knowing about stale neighbouring sentences, looking for them, and
finding none is entirely consistent with having broken the container's claim.

**Worked once, here, on this very section.** The `##` heading these subsections sit
under opens *"These two are the same disease…"*, and there are now five of them —
which looks like the same defect until the question is actually asked. It is not:
"these two" names the two TICKETS the section was written about (#684 and #687),
and master already carried a third subsection under it before any of this. The
claim is scoped to two findings rather than to the subsection list, so a further
subsection does not falsify it. That analysis is recorded because the next person
will otherwise redo it — and because *asking and finding the claim intact* is the
outcome this rule expects most of the time. A rule whose answer is always "you
broke something" is one people stop asking.

**A counted heading is itself the weaker half of this**, and the BUILD lane reached
it from the other side: *"Six ways"* counts **instances, not bullets** -- five
bullets, two of which describe two instances each -- and the unit is nowhere
stated, so the number is unfalsifiable by reading and grows wrong as the section
does. Its proposal is to drop the number from that heading. The two findings are
one finding: this rule says an insert must check the container's claim, and that
one says a container should avoid making a claim nobody can check. Neither
supersedes the other, and the BUILD lane's branch touches this same file.

### A counterfactual must be RE-RUN after a refactor -- a refactor can move what it was catching

**A counterfactual establishes that a guard bites the code as it is written. Rewrite
the code and it establishes nothing, even when it still passes** -- and the way it
fails is to keep passing while testing something that is no longer the risky part.

Measured on #658. The decision "does this rejection reason predict the hazard the
winning launcher carries" started as a hardcoded predicate inside a function, and
its counterfactual was to widen that predicate: doing so warned on three rejection
reasons that must stay silent, and the check went red. Good guard.

The `/simplify` pass then made it **data-driven**, which was the right call for an
otherwise strictly table-driven file: the pattern became a `predicts` column on the
candidate row, and the decision became winner-agnostic. Every row of the check
stayed green, as it should have -- the behaviour was unchanged.

Then the same counterfactual was re-run against the new shape. **Widening the
column to `.` left every row green.** The check drove the pure function with a
pattern of its OWN and never read what the module declared, so the column -- the
thing a maintainer would actually get wrong -- was covered by nothing at all.

**The generalisation had relocated the untested part, and looked like an
improvement while doing it.** That is the clause that makes this a rule rather than
an anecdote: the refactor was correct, the tests were green, the design was better
by every stated principle in this file, and the guard had quietly stopped guarding.
Nothing in the diff, the review or the suite said so. Only re-running the
counterfactual did.

The repair is the same idiom as everywhere else here -- **read the literal from the
file that owns it, never restate it.** The check now reads the `predicts` column out
of `cmake/portable/CompileCache.cmake` and `UnsupportedVersion`'s `.name` out of
`src/Pace/Protocol/CompileCacheWire.hpp` and asserts they agree, which also
closed a pre-existing coupling nobody had connected: the launcher reports the wire
name, and a rename there would have disarmed the warning with every test green.

So:

> **When a refactor moves the thing a counterfactual was aimed at, the
> counterfactual moves with it. Re-run it against the new shape and watch it fail,
> or it is now asserting something you did not intend to assert.**

Two things this is NOT. It is not an argument against generalising -- the column is
the better design and stays. And it is not the "deriving is necessary and not
sufficient" rule above wearing a different hat: that one is about a guard that was
never sufficient, this one is about a guard that WAS sufficient and stopped being,
without anybody touching it. A green suite distinguishes neither.

## A configure's OUTPUT is the module's claim; the generated buildsystem is the artefact

<!-- agent-tripwire: A configure's OUTPUT is the module's CLAIM; the generated buildsystem is the artefact -->

`check-compile-cache-caveat.cmake` asserted entirely on what a configure PRINTED --
every row comparing against `${configureOutput}${configureError}`. So it proved what
`CompileCache.cmake` **says** and never what it **wired**, and a row could print
`-- [cache] Enabling sccache ...` with the full caveat, at the right severity, while
the generated build carried no compiler launcher at all, and every assertion passed
(#187).

The cache cannot answer this. The module sets `CMAKE_C_COMPILER_LAUNCHER` and its CXX
sibling as NORMAL variables, never cache entries, so `CMakeCache.txt` is silent --
measured across eleven build trees on one workstation, unset in every one, five of
them demonstrably running sccache on every compile. What carries the decision is the
generated buildsystem: Ninja emits a per-rule `LAUNCHER = <path>`, and the Makefile
generators put the program at the head of the compile command in `build.make`.

Three things the fix needed that the ticket did not name:

- **The fixture had no target**, so it generated no compile edge and there was
  nothing to read. A project that only calls `project()` and includes the module
  proves the module's prose and can prove nothing else. It has an OBJECT library
  now, defined after the include so the launcher variable is in scope, and still
  never built.
- **The two stand-in launchers had to DIFFER.** Both were `${CMAKE_COMMAND}`, which
  makes the assertion a presence check: it can say a launcher was wired and not
  which, so `sccache-not-preferred` -- whose entire claim is that ccache won over
  sccache -- would still rest on a status line. They are `${CMAKE_COMMAND}` and
  `${CMAKE_CTEST_COMMAND}` now, two real programs a CMake script can always name.
- **A generator whose buildsystem the reader cannot parse is a THIRD state**,
  reported by name rather than folded into *no launcher was wired* -- and if the
  generator IS one the reader claims to handle and it read NOTHING, that is a
  violation, because every row's wiring assertion is then vacuous. The rule that
  guards a check against reporting clean has to guard this check too.

Proved by breaking it, not by assuming: with the module's two `set(...LAUNCHER)`
lines replaced by a comment -- so it prints `-- [cache] Enabling sccache
(/usr/bin/cmake) for C/C++ compilation` and the caveat, and wires nothing -- the
check refuses with exactly three violations, the three rows that expect a launcher,
and none of the three that expect none.

**And the first version of it was GREEN on Linux and red on all three Windows legs,
for one and the same file.** `build.ninja` writes

```
LAUNCHER = "C:\Program Files\CMake\bin\cmake.exe"
```

-- QUOTED, because the path holds a space, and with BACKSLASH separators -- while
`${CMAKE_COMMAND}` is `C:/Program Files/CMake/bin/cmake.exe`. A `STREQUAL` over those
is false for a path that is the same path, and on Linux the two spellings are
byte-identical, so the green run there could not have shown it. That is the
platform-arm hazard reaching a `cmake -P` check: **a comparison written against the
spelling one generator on one platform happens to emit is a comparison nobody has
tested.** Normalise a path as a PATH -- a matched surrounding quote pair is the
generator's escaping, `file(TO_CMAKE_PATH)` settles separators, and case folds only
where the filesystem folds it -- and normalise BOTH SIDES, or the two are normalised
asymmetrically, which is its own way to compare two things that were never the same
shape.

The measured strings are in the check's own comment rather than described, so nobody
simplifies the normalisation away on the platform that does not need it. And the
mutation was re-run **on Windows**, not only on Linux: a normalisation's whole risk
is accepting too much, so "it stopped failing" is not the same claim as "it still
bites". Same three violations there, same exit 1.

**And the decision a guard makes is what gets tested, not the acquisition around
it.** `tidy-sweep.sh`'s canary -- the thing that stops a whole branch being reported
clean by an analyser that never ran -- needed clang-tidy, a compile database and a
real translation unit, so it could only be exercised on a machine already running a
full sweep, which is the population it is not for. `CanaryVerdict` is now a pure
function over `(exit status, output)` driven by `--self-test`, which is already a
registered ctest on every platform (#257). Its two failing arms are NOT one: an exit
at or above 126 is the shell saying the program never started, with no output, while
the pattern arm is a binary that DID start and analysed nothing, exiting normally.
And `ok` for every other non-zero exit is deliberate -- clang-tidy exits non-zero
when it has FINDINGS, so a canary refusing that would refuse every branch with
something to fix. Neutered to `echo ok`, exactly the five refusing cases fail and the
two accepting ones stay green.

## A branch behind master is unverified, and only a build says otherwise

<!-- agent-tripwire: A branch BEHIND master is unverified, and only a build says otherwise -->

A pull request's CI ran against the master it was branched from. Every green check
on it is a statement about *that* tree, and it stays a statement about that tree
however many times it is re-read. When master has moved, the only thing that
restores the claim is building the branch on top of what master is now.

Two ways of judging that risk without building are in use, and both are wrong.

**The amount a branch is behind is not a measure of the risk.** It is a measure of
elapsed time, and the defect is a semantic collision that either exists or does not.
One commit can change a signature every branch calls; a hundred can be documentation.
A branch that is two behind and a branch that is twenty behind are equally unverified,
and ranking a queue by that number sorts it by nothing.

**File overlap is evidence only in the direction that says there IS a hazard.**
Two branches touching one file will conflict, or will merge into something neither
author read -- worth knowing. But **the absence of overlap is evidence of nothing**,
and reading it as safety is how this gets missed.
[#520](https://github.com/LASTRADA-Software/pace/pull/520) and
[#525](https://github.com/LASTRADA-Software/pace/pull/525) share no file at
all: #520 changed `IConnector::Connect`'s third parameter from
`std::chrono::milliseconds connectTimeout` to `DialOptions options`, across
`IConnector` and every connector implementing it; #525 adds callers of `Connect` in
`FrameEndpoint`, a file #520 never touches. Both pairwise CI runs were green, and
both were green *correctly* -- each was built against a master without the other.

Neither branch has ever gone red, and that is not a contradiction: it is the point.
The break exists only in the combination, and the combination is the one tree nothing
built. A red run cannot warn about a tree that was never compiled, so the absence of
one here carries no information at all.

A compiler finds this in seconds and no amount of reading finds it: the hazard is a
name shared between two changes, not a line shared between two diffs, and a diff
cannot show a name it does not mention. Which is also why cost is not the argument
against doing it -- the N lane's worktree for
[#292](https://github.com/LASTRADA-Software/pace/issues/292) was nine commits
behind, and rebasing and rebuilding it took about two minutes and came back clean.
That is what the check costs when it passes -- and passing is what it usually does,
which is precisely why skipping it feels free.

So the sequencing rule is that a branch is rebased and rebuilt before it merges, not
inspected; `gh pr update-branch --rebase` is what converges a queue. And where two
branches are in flight at once, the second one's green is provisional until it has
been built on the first.

**And the diff that VERIFIES such a rebase landed intact is three-dot.** `A..B` diffs
the two endpoints, so when `B`'s history carries commits `A` lacks -- which is the
ordinary state during a rebase, and the state every branch is in once its base has
moved -- it folds those changes in too and answers a question nobody asked. `A...B`
diffs `B` against the MERGE BASE, which is the question actually being put: what does
this branch change relative to where it diverged.

Measured while checking that a rebase had landed intact
([#541](https://github.com/LASTRADA-Software/pace/issues/541)): the two-dot form
reported `expect=-35` against `delta=10` -- a 45-line discrepancy that reads exactly
like a dropped hunk, and was reported as one. The three-dot form over the same pair
agreed with the expectation exactly, and nothing had been dropped.

The distinction is textbook git, and that is not what makes it worth a bullet. **The
wrong form produces a plausible NUMBER rather than an error**, and a plausible number
inside a verification step is indistinguishable from a real finding until something
else contradicts it. That is this section's own failure direction arriving one step
later: the bullets above are about a merge that was never built, and this is about the
instrument that checks the merge, confidently wrong in the same way.

**The two forms disagreeing IS the discriminator, and it is not an error.** It says the
branch is behind its base -- which is precisely the precondition the sequencing rule
above turns on, arriving for free out of a diff somebody was running anyway. Read it as
a finding about the branch, never as a fault in the diff.

Checked across every tracked file at #541 rather than left unmentioned, since
*"checked, none"* and *"did not check"* must not read alike: the three range usages in
this tree -- `scripts/ci-scope.sh` twice and `scripts/tidy-sweep.sh` once -- are already
three-dot, and none needed changing. The census was run with a positive control, a
planted two-dot range, because a grep that finds nothing has said nothing until it has
been shown finding something.

### After a revert, test for the REVERT and never for the defect

**A revert leaves the reverted commit in the ancestry forever.** `git revert` writes a new
commit that undoes a change; it does not remove the change from history. So
`git merge-base --is-ancestor <fix> <branch>` answers **YES for every branch that has ever
seen the fix**, including every branch that also carries the revert and therefore does not
have the fix's behaviour at all. The predicate discriminates nothing, and it answers in the
direction that reads as reassurance.

**The only useful question is `--is-ancestor <revert>` coming back NO.** That is the one
fact that distinguishes a tree where the change is in force from a tree where it has been
taken out again, and it is asked of the revert commit rather than of the original.

What makes this worth writing down is that **the instinct is to check for the thing that
broke you**, and that is the one test that cannot work here. Somebody asking *does this
branch have the fix* will reach for the fix's SHA, get YES, and stop — with a green answer,
a correct command and a wrong conclusion. Same failure direction as every other entry in
this file: the instrument answered honestly about something other than its subject.

### A subject line is an abbreviated identifier with no prefix to disagree about

**Two commits in this repository carried the identical subject line and opposite revert
status.** Two people asked *which commit is this* by matching the subject, both measured
correctly, and they reported contradictory answers — with nothing in either reading to say
which commit had been looked at.

A truncated SHA at least *looks* like an identifier, so it invites the comparison that
catches the mistake: two prefixes that differ are visibly two objects. **A subject line
looks like a description**, so nobody compares it against anything — it reads as a label
for a change rather than as a name for one object among several that may share it. The
abbreviation rule from [`testing.md`](testing.md) — *an abbreviated identifier is a DISPLAY
form; the full one is read, never padded, truncated or re-derived* — covers this, and the
subject line is the member of the family that does not announce itself as one.

The same shape recurs wherever a display string is pressed into service as a key: a ctest
index, two worktrees one token apart in their paths, and **a leg name without its
compiler** — so **a leg travels with its compiler and its machine**, or two people
comparing `Debug` against `Debug` are comparing different builds on different hosts.

## A rulebook entry that has gone false instructs the next person

<!-- agent-tripwire: A rulebook `## Open work` entry names an OPEN issue, or it is a rule that has gone false -->

Every `## Open work` entry in this directory names an issue that is still open, and
`ctest -R rulebook-open-work` is what says so. Seven of thirty-nine did not when the
check was written (#619) -- and the cost is not the minute a reader spends on a
finished residual. It is the shape #395 found: an entry asserting that a field's
borrow *"cannot be tested"*, with a plausible short-string-optimisation argument
attached, in a file `AGENT.md` routes every session to before they touch `Net/` or
`Protocol/`. The rulebook was telling the next person **not to attempt** the guard,
in the register of a current argument rather than a stale one. An ASan trace
disproved it directly: allocated, freed, read, three lines apart.

Four things about that check are load-bearing, and three of them are the difference
between a check and a check-shaped thing that passes:

- **An entry is the bullet's LEADING reference; a citation in its prose is not one.**
  #619's own measurement named `#195` twice as a stale entry. Both are citations
  inside *another* bullet -- "#200 … since #195 that banner is the compiler's
  identity" -- naming the landed change that CREATED the residual, and both are
  correct as written. A check built to that description invents findings on a correct
  rulebook, somebody edits a correct entry to satisfy it, and it gets disabled for
  noise. What makes the narrow reading safe is the refusal beside it: a top-level
  bullet in such a section that opens with no issue link is `unparsed-entry`, so a
  reformatted bullet cannot quietly leave the scanned set.
- **The object's KIND is asserted, not only its state.** `gh issue view <n>` falls
  back to pull requests and so does `repos/{owner}/{repo}/issues/N`. The failure is
  asymmetric: a MERGED pull request answers `closed`, fails a `state == open` test,
  and *looks like the check working* -- while an OPEN one answers `open` and passes
  while naming no issue at all. Resolving to the wrong kind of object is a way of not
  having resolved it.
- **There are FOUR outcomes: pass, stale, bad-reference, could-not-run.** Measured:
  a nonexistent issue, a repository that is not there, and a bad token all exit 1
  with an empty result, and **two of those three are faults in the checker's own
  invocation**. Reading `exit != 0` as *this entry names a dead issue* makes the
  check blame its subject for its own fault -- it invents a finding, and the repair
  is somebody editing a correct entry. The verdict comes from the HTTP status, and
  `gh api rate_limit` is asked first as a liveness anchor, so a broken checker is
  told from a broken rulebook before either could be blamed. Without that anchor one
  typo in a repository slug is a 404 on every entry: thirty-nine findings from one
  mistake, each of them saying the wrong thing.
- **A self-test whose only negative case is a closed issue passes under all three of
  those bugs.** `rulebook-open-work-selftest` drives a case per outcome against a
  stub `gh`, plus the open-PR and merged-PR cases, plus a control that must PASS and
  a citation-of-a-closed-issue case that must also pass.

And the markdown side is where a narrow pattern hides, which is the same defect one
layer down. Four shapes were measured passing a closed issue or refusing a correct
file before they were fixed, none of them exotic: a `*` or `+` bullet, or a
one-space-indented `-`, was not a *bullet* at all — so it became no entry AND reached
no refusal, and simply vanished; a fenced markdown SAMPLE containing `## Open work`
opened a real section, so the check reported `stale` about a documentation example
and told the reader to delete it (`README.md` carries such a sample); a fenced repro
block inside a real section was refused as `unparsed-entry`; and a heading test of
`^#` rather than `^#+ ` refused wrapped prose beginning `#340; …`, of which this
rulebook has four lines. An emptied section was also only refused when the whole FILE
emptied. The lesson is the one the refusal was written for: **a refusal is only as
wide as the pattern that feeds it**, and every one of these was found by constructing
the input and running it rather than by reading.

The network decision is explicit rather than implied. `rulebook-open-work` is the
grammar and opens no socket, so it is in the default set; `rulebook-open-work-state`
resolves and is `smoke`. Folding the first into the second would make a machine
without `gh` skip the assertions that need nothing. What may skip is bounded to a
missing PREREQUISITE detected BEFORE any entry is resolved; a fault appearing
mid-run, with some entries already resolved, is a FAILURE, because a partial answer
over a set is not an answer about the set. A repository probe that fails on anything
but 404 is the prerequisite case and not a finding — it shares a rate limit and a
transport with every query behind it, so treating it as one is a new way for a
healthy rulebook to go red.

And the GRAMMAR half carries the `docs-subject` label, which is load-bearing rather
than tidy: `ci-scope.sh` classifies `.agent/**` as docs-only, every `linux` job is
gated on that, so a pull request editing only `.agent/rules/*.md` runs **no ctest at
all** — the ungated doc-subject step is the only thing that runs. Unlabelled, this
check would be green-by-absence on exactly the change class that edits an Open work
entry. The resolving half stays out, because that step is inside the required
`Check C++ style` context and a required context that needs credentials and a network
fails for reasons that are not about the tree.

An emptied or renamed heading is refused for the reason `node-config-reference`
carries: two empty lists agree perfectly, so a `## Open Work` or a heading with
nothing under it would take one file's entries out of the scanned set forever while
the total stayed healthy.

## A diagnostic that never RAN and one that ran and found nothing are the same green

<!-- agent-tripwire: A diagnostic that never RAN and one that ran and found nothing are the same green -->

**`continue-on-error` is right for a diagnostic and is exactly what hides one that could
not start.** A probe added to `Package (macOS .pkg)` to settle #376 staged its helper with
a here-document, which had to survive YAML's literal scalar **and** bash's parser. It lost
on both -- the delimiter carried shell-escaping that means nothing inside `run: |`, and it
was indented, which `<<` does not strip. Bash never matched the delimiter, swallowed the
rest of the script as heredoc body, and the step printed three lines and stopped.

**The job reported SUCCESS.** Which is the defect #376 and #682 are both about, reproduced
inside the probe written to settle one of them.

- **Keep `continue-on-error`.** The flag is not the defect and removing it breaks the
  pattern: a diagnostic that can redden a packaging job teaches people to ignore packaging
  reds. What was missing is the **assertion that the classifier was reached at all** --
  a verdict surfaced as `::notice`, its absence as `::warning`, so *answered nothing* is
  visible in the UI rather than buried in a green log.
- **Three outcomes, never two.** A probe that can only answer the two you expect will
  answer one of them whatever it sees. `INCONCLUSIVE` is a verdict.
- **A green test on the wrong object is worse than no test, because it RETIRES THE
  SUSPICION.** This is the finding; executing the workflow's own `run:` block is only its
  remedy, and a remedy does not transfer to the next instance the way the finding does.
  The broken probe's decision logic had been driven against three fake `xcrun`s and was
  **correct the entire time** -- so every test passed, every test was honest, and every
  test told me nothing. Had there been no test at all, the step would still have been
  suspect and someone would have looked at it. **The passing suite is what stopped anyone
  looking.**

  So the question is never "is this tested" but "is the thing tested the thing that
  ships". Here they differed as *text*: a reconstruction of the step, versus the step. The
  repair is to extract the `run:` block out of the workflow and execute **that** -- a
  reconstruction tests your understanding of the artifact, which is the part that was
  already right.

This is the same family as the entry below, one layer out: there the local run and CI read
different **trees**; here the tested script and the shipped script were different **text**.

## A green local gate says NOTHING when the subject under test is the build environment

<!-- agent-tripwire: When the SUBJECT under test is the build environment, a green local gate is not weak evidence -->

**Measured across one change, in one afternoon: three platforms, three defects, none of
them visible locally.** A check that measures which translation units the analyser sees
went green on the local gate and then failed CI three times running:

<!-- table-total: none -->
| platform | defect |
|---|---|
| Linux (`clang-asan-ubsan`) | the third-party filter was a **denylist** naming `/_deps/`, and CI caches CPM sources under `.cache/CPM/` **inside the repository**, so ~40 vendored units read as analysed-by-nothing and the check refused a healthy tree |
| Windows | the selftest's fake `nm` was a POSIX shell stub spawned through Python -- `CreateProcess`, **ENOEXEC** |
| macOS | **bash 3.2 cannot parse a here-document inside a command substitution**, so the check died at PARSE time and all eight selftest cases refused for a reason unrelated to what they test |


**They are one failure, not three.** The subject under test was the build environment, and
that is the one variable a local run holds fixed. So the rule is stronger than "a local
gate says less here": **on this class of change it says nothing**, and a green one is not
weak evidence but no evidence.

Three rules fall out, each generalising past this change:

- **An exclusion list is a bet on the world's layout; an inclusion list is a statement
  about your own.** `/_deps/` was not the wrong *path* -- a denylist was the wrong *shape*,
  because it can only be right about locations it already knows. An allowlist naming this
  project's `src/` cannot be wrong about a directory it never mentions.
- **Knowing a rule and having just applied it is not protection.** That Windows ENOEXEC is
  the same defect the same author had fixed in another selftest **three hours earlier**,
  reproduced in a file written afterwards -- and the bash 3.2 hazard was already written
  down in this file. **A fix that is not structural does not transfer to the next file you
  write**, which is the argument for the scan living in its own `.py` sibling rather than
  as a heredoc, and for registering a check by its SUBJECT (what the *Linux* sweep cannot
  see) rather than by its mechanics.
- **A local run and a CI run can read different trees without either being wrong.** Catch2
  is a distribution package on the developer host and a CPM checkout in CI, so its sources
  were never in the local compile database at all. Not a misconfiguration -- two
  environments answering honestly about themselves.
- **A POSIX shell REWRITES the arguments it hands a native Windows tool**, and the check
  that measures analyser coverage is a shell script driving a compiler. Measured on the
  Windows leg's first real run: Git Bash turned `clang-cl ... /nologo` into
  `clang-cl: error: no such file or directory: 'C:/Program Files/Git/nologo'`, so all six
  units the leg exists to cover came back `unknown`. `MSYS2_ARG_CONV_EXCL='*'` and
  `MSYS_NO_PATHCONV=1` are the MSYS2 and Git-for-Windows spellings of one switch; set
  both, since nothing on a POSIX host can tell you which runtime is present. **The LOUD
  half is the lucky half.** The same command line also kept `/c` and `/Fo<obj>`, because
  the strip knew only the GNU spellings -- and that one SUCCEEDS: the preprocessed text
  goes to the object file, stdout is empty, and the classifier honestly answers `empty`.
  Not `unknown`. So the leg added to close a blind spot would have printed
  `TIDY SWEEP CLEAN (0 of 6 file(s) contributed code)` and exited **0** over the exact
  files it was added to read -- measured against the pre-change script, not argued. The
  fix that makes that unreachable is not the strip: it is that **a mode which NAMES its
  set may not report clean over a member it could not cover.** `--all` chose its own set,
  so an empty unit there is the guard working; `--only` was handed one, so an empty unit
  is the run failing to do what it was asked. Both spellings of a driver's flags are a
  TABLE keyed on the driver NAME, never a sniff for a leading `/` -- on POSIX that starts
  a path, which is the compile-cache rule arriving from the other direction.

### A suite run on a Windows host failed for the HOST, and every entry said it was the tree (#1355)

Three causes, each MEASURED by running the entries on that host, and none of them visible
from Linux. Each one presented as a defect in the tree under test -- a scan "broken, not the
tree", a `git` fatal, a shallow clone -- so a lane meeting them either investigated a branch
that was fine or learned to ignore the names, and an ignored red is a disarmed check.

<!-- table-total: none -->

| where `ctest` ran | cause | what the entries said | what closes it |
|---|---|---|---|
| Git Bash, with `MSYS_NO_PATHCONV=1` and `MSYS2_ARG_CONV_EXCL='*'` exported | every check INHERITED the switch, and a check spelling a POSIX path (`pwd` is `/d/...`, `mktemp` is `/tmp/...`) to a native program relies on the conversion it turns off | `mkdocs-validation`: `/d/...\mkdocs.yml does not exist -- the scan is broken, not the tree`; `script-modes-selftest`: `fatal: cannot change to '/tmp/...'`, exit 128; `workflow-script-invocations`: exit 128 and nothing else; `node-reloadable-docs-selftest`: no tracked file carries its marker; `reactor-teardown-gate-selftest`: the canary does not exist; and the `smoke` entry `pacectl-e2e`, registered without the wrapper: the daemon DIED, on a config file `/tmp/.../empty.yaml` that did not exist | every test `src/tests/CMakeLists.txt` registers starts without the switch on Windows, a DEFERRED `ENVIRONMENT_MODIFICATION` so a registration appended later is covered too; `run-check.sh` unsets it as well, for a check run by hand |
| PowerShell, or a Visual Studio developer shell | a bare `bash` resolved to `C:\Windows\System32\bash.exe`, a launcher for WSL's LINUX bash, ahead of Git on that PATH | 53 of 136 `hygiene` entries: `No such file or directory` | `PACE_BASH` on Windows is Git for Windows' `bin/bash.exe`, found beside `GIT_EXECUTABLE` and asked for `MSYSTEM` |
| WSL over DrvFs, in a worktree the Windows git created | the absolute `gitdir:` pointer, which WSL git cannot follow | `workflow-script-invocations`: exit 128, silent; `unguarded-prerequisites-selftest`: *"a shallow clone must fetch depth 0"*; `node-reloadable-docs`: no tracked file carries its marker; `unguarded-prerequisites`: enumerated by directory WALK; `local-gate-selftest`: `no-headers` | `run-check.sh` refuses a check in a git tree the git on PATH cannot read, before it starts, printing `repair-worktree-pointers.sh`'s diagnosis; `local-gate.sh`'s live header case names the same cause |

Measured, with the switch exported: the five wrapped entries fail -- exactly those five --
with no unset anywhere, and pass with the switch not exported; `pacectl-e2e` failed
twice running with it and passed twice without. With the deferred property alone, and both
script-level unsets removed, all six pass. From PowerShell the full native suite ran 4061
tests with none failing.
Under WSL in the unreadable worktree, 65 of 168 `hygiene` entries failed and all 65 named the
unreadable work tree; after `repair-worktree-pointers.sh --apply`, none failed.

- **The conversion switch belongs to the SPAWN that needs it, never to an environment a
  suite inherits.** The bullet above says to set both spellings, always, and it is right about
  a compiler invocation. Exported into the shell that then runs `ctest`, the same two lines
  reach every check, and the entries that break are the ones written correctly for a POSIX
  host. A check that needs the switch -- `check-banner-probe-identity.sh` -- already pins it
  itself, which is the only place that can know.
- **"Git for Windows' bash is the only one there" was a claim nobody had measured**, and it
  lived in the comment above the registration it justified. A Windows host with WSL has two
  more, both ahead of Git on PATH in the shells that are not Git Bash. CI's Windows legs run
  `ctest` from `pwsh` and pass, which says that image puts Git first -- inferred from their
  being green, not read from a log.
- **An unreadable work tree is a REFUSAL, not a skip.** A skip is green, and a `hygiene` label
  reporting green over checks that never asked git anything is the collapse `run-check.sh`
  exists to remove. What it does NOT cover: a tree with no `.git` entry and a host with no
  git both still run, by the walk their checks carry, since neither has a git answer to be
  wrong about.
- **The ticket named six entries and they were two things.** Five were the conversion switch.
  The sixth, `e2e-helpers-selftest`, is not registered on Windows at all -- `if(NOT WIN32)`
  since `26d8ac60`, before the ticket -- and its reported "120 s" was the CALLER's foreground
  cap on a run by hand that exited 0, not the registration's `TIMEOUT 120`. Under WSL it
  took 69 s at `-j 8`.
- **And a full run found one more that no single-entry run would.** `RefusalNotice: two
  daemons and two causes throttle separately` failed once at `-j 16` and passed alone. It
  wrote its stamps into a bare `UniqueScratchPath`, never cleared and never removed, at a
  FIXED epoch -- so a leftover from an earlier run whose pid Windows handed out again read as
  *announced a second ago*. Staged by planting a leftover for every multiple of 4 below 65536
  (76 real ones were already in `%TEMP%`): 5 of 5 runs failed, and 0 of 5 once the case took
  `ScratchDirectory`, which clears first. A pid separates LIVE processes; it does not separate
  a live one from a dead one's leftovers unless something clears them.

## A build under WSL is I/O-bound on the Windows drive mount, not CPU-bound

<!-- agent-tripwire: A build under WSL is I/O-bound on `/mnt/<drive>`, not CPU-bound -->

**The build TREE must not live under `/mnt/<drive>`.** Under WSL2 that is a **9p** mount
(DrvFs under WSL1), where every `open` and `stat` is an RPC to the Windows side, and a build
is millions of them; the Linux root is ext4. The SOURCES may stay there -- git, the Windows
toolchain and an editor all reach them, and the measurement below kept them there -- but the
objects, archives, depfiles, link outputs and `.ninja_deps` must not:

```sh
cmake -S /mnt/d/<worktree> -B "$HOME/bld/<name>" -G Ninja      # tree on ext4, sources on 9p
```

**This is stated as a MECHANISM and not as a path**, because the next machine has a different
drive letter, a different distro and possibly WSL1. What transfers is *the build tree does not
belong on a filesystem reached over a protocol*; what does not transfer is any of the numbers
below.

### git in a work tree both operating systems use re-hashes every tracked file

The sources staying on `/mnt/<drive>` has one cost that no build-tree move removes, and it
reads like a hang. **Windows git and WSL git in one work tree each re-hash every tracked file
after the other has run.** The index caches per-file stat data, and the two record different
stat data for the same DrvFs file. Each therefore finds every entry changed, and re-reads and
re-hashes the whole tree over 9p before it can answer. A configure meets it whenever the other
operating system's git touched the index last: `cmake/Version.cmake` runs `git status` for the
version string's dirty suffix, so a lane that alternates a Windows `cl-debug` configure with a
WSL gate configure in one worktree pays it on every WSL configure.

Measured on 2026-09-28, in one worktree on `/mnt/d` (1,355 tracked files), WSL git 2.53.0 against
Git for Windows, `git status --porcelain --untracked-files=no` timed with a monotonic clock at
load1 of about 5-6:

<!-- table-total: none -->
| sequence | WSL `git status` |
|---|---|
| WSL after WSL, three times | 1.90, 1.94, 1.96 s |
| WSL after a Windows `git status` (0.27-0.32 s), three rounds | 9.30, 8.88, 8.66 s |
| WSL after WSL again, twice | 1.76, 1.81 s |

About 4.6 times the cost, and it grows with load: the first WSL status after a Windows build of
that tree took 148 s (load1 1.55 when it started, rising past 20 during the session), and in the
same session the TAG `describe`,
which never touches the work tree, once took 26.8 s. So **a git query on `/mnt/<drive>` has no
bound worth writing down**, and no cheaper command removes the re-hash: any correct dirty
check must stat every tracked file. `--no-optional-locks` makes it worse, since it never writes
the refreshed index back, and `diff-index` without a refresh reports every stat mismatch as a
change.

That is why `cmake/Version.cmake` does not treat a query that did not answer within its bound
as a negative. It names what that query lost -- the tag, the distance, or the dirty state
(`-dirty-unknown`) -- and makes the version Provisional, which `PACE_REQUIRE_EXACT_VERSION`
refuses. The 20 s bound stays: raising it hides the cost this section names.
`ctest -R version-git-unanswered` drives each query past a small injected bound.

### The measurement, pinned (2026-09-18)

Conditions are PINNED here and deliberately do not point at their source: a measurement's
conditions are the world at one instant, and a pointer would let an unrelated edit silently
re-attribute a real reading to conditions it was never taken under.

<!-- table-total: none -->
| condition | value |
|---|---|
| host | Ubuntu 26.04.1 LTS under WSL2, 32 cores, 45 GiB |
| filesystems | sources and arm A/D tree on 9p (`/mnt/d`); arm B/C tree on ext4 (`/dev/sdd`) |
| compiler | g++ 14.3.0, `CMAKE_BUILD_TYPE=Debug`, `-j 32` |
| linkers | GNU ld 2.46, mold 2.40.4 |
| launcher | `USE_COMPILER_CACHE=OFF` in every arm, or the reading is of the cache |
| CPM cache | warm and shared by both arms, already on ext4 |
| commit | `0f38bd77`, both trees identical afterwards at 4.7 GB / 4737 files |
| swap | **0 pages in every phase** -- 32 parallel C++23 TUs against 45 GiB can page, and a paging run measures the memory ceiling while looking exactly like a slow filesystem |

<!-- table-total: none -->
| arm | configure | cold build | relink |
|---|---|---|---|
| 9p + GNU ld | 78.5s | 450.6s | 188.1s |
| ext4 + GNU ld | 52.6s | 131.5s | 8.3s |
| ext4 + mold | 33.5s | -- | 6.1s |
| 9p + mold | 44.9s | -- | 30.3s |

**The build tree alone is 3.4x on a cold build and 22.6x on a relink**, with the same
compiler, the same linker and the sources left on 9p. The relink figure is the one a day is
made of: edit one file, rebuild, and the wait goes from 188s to 8s.

**mold is real and secondary, and its shape is the interesting part.** It is worth 1.36x on
ext4 and **6.2x on 9p** -- the win is largest on the filesystem you should not be using,
which inverts the usual "a faster linker is a faster CPU" story: most of GNU ld's cost here
is I/O, which 9p amplifies and mold largely avoids. And 9p+mold (30.3s) is still 3.6x slower
than ext4+GNU ld (8.3s), so **mold compensates for the wrong filesystem rather than
substituting for the right one.** Install it (`apt install mold`) and pass
`-DCMAKE_EXE_LINKER_FLAGS=-fuse-ld=mold` with the shared and module pair beside it.

A cold build under mold was NOT measured; linking is about 8s of ext4's 131.5s, so it can
only move that figure by a couple of percent. That sentence is an inference from the other
two readings and is marked as one rather than written as a third.

### Parallelism is derived from the host, and said out loud

**A `-j` inherited from a script is a number chosen for no machine.** Every build in the
session that produced this section ran `-j 6` on a 32-core host, because 6 was what the
script said. Derive it (`-j "$(nproc)"`, or let ninja default to `nproc + 2`) and print what
was derived, for the reason a benchmark states its build before any figure.

**And a local shell inherits NONE of CI's environment**, which is where the suite goes
quiet: `CTEST_PARALLEL_LEVEL` is set once in `build.yml`'s `env:` precisely so every ctest
invocation inherits it, and a WSL shell has no such thing -- so a local suite runs **serial**
unless it is set, and nothing says so. The figure justifying it lives in that file's own
comment and is deliberately not restated here.

Not `nproc` for the SUITE, though: these tests are themselves multi-threaded -- reactors,
thread pools -- so 1:1 process-to-core oversubscribes and manufactures bounded-wait
timeouts, which present as flakes rather than as a slow run. CI's 4-on-4 is 1:1 only because
a hosted runner's tests are short and single-threaded.

**The configuration is validated rather than merely faster:** the whole suite passes from an
ext4 tree -- 4902 tests, 0 failures, 153.5s at `CTEST_PARALLEL_LEVEL=16`. A rule recommending
a layout nobody had run the suite in would be this file's own *a fixture that has never
completed has told you nothing*, one level up.

### The gate does this itself (#1227)

`scripts/local-gate.sh` owns `out/build/gate-clang-debug` and `out/build/gate-gcc-release`
**under the source directory**, and it keeps owning those paths. What changes is where they
POINT: when the root is on a filesystem in `protocol_filesystems` and the build home is not,
each becomes a symlink into `${PACE_GATE_BUILD_HOME:-$XDG_CACHE_HOME/pace/gate}`,
and every run says which it decided.

- **A symlink, not a path threaded through the script.** The build directory is spelled once,
  and CMake records the SPELLED path in its cache rather than the resolved one, so
  `cmake --build --preset` and a re-configure agree with it -- probed through a 9p-to-ext4 link
  before anything depended on it. `cmake -B` beside `--preset` is the tempting alternative and
  moves only the configure; the build step reads the preset's own `binaryDir`.
- **Keyed per worktree, and the key is CHECKED.** Two worktrees sharing one build tree would
  give one of them a verdict built from the other's sources -- the failure this file exists to
  refuse. The home is a digest of the root, it records its owner in `ROOT`, and a home naming
  any other root is REFUSED rather than reused, compared WHOLE so a prefix is another tree.
- **It sidesteps the hazard the ticket feared rather than managing it.** #1227 assumed a
  WSL-native gate meant building a COPY of the tree, with every hazard a copy carries: a stale
  mirror, a dirty tree sampled at a third moment, a `.git` pointing back at a Windows path.
  Moving only the OUTPUT keeps the gate building the real tree; there is no copy to go stale.
- **An `unknown` is its own answer.** A root whose filesystem could not be asked -- no
  `findmnt`, as on macOS -- stays in the tree AND says why, rather than being read as local.
- **The table is the measured one.** `9p` and `v9fs` (one WSL2 mount, two spellings) and WSL1's
  `drvfs`. NFS, CIFS and sshfs are protocol filesystems too and are left out on purpose: nobody
  has measured a build on them here, and the next row comes with its measurement.
- **Nothing is deleted.** An in-tree build left by an earlier gate is moved aside and named.

**The first real run through it**: `bash scripts/local-gate.sh` on `c4010d87` from a 9p root
**passed** in 1412 s wall, both legs, 4909 and 4904 tests, 0 failed, with both build directories
reported and found on ext4. That is a statement that the placement WORKS, not a speedup figure:
no gate was timed from a 9p build tree under the same conditions, so none is claimed here.

**What it does NOT reach, measured and ACCEPTED rather than deferred**: the hygiene checks that
walk the SOURCE tree still read it over 9p, because the sources stay where git and the Windows
toolchain can reach them. One pass of `ctest -L hygiene -j 8`, the same commit, sources on each
filesystem (pinned, 2026-09-18, the host of the table above):

<!-- table-total: none -->
| sources on | wall | summed test time | host load at start |
|---|---|---|---|
| 9p | 92.6 s | 735 s over 227 tests | 0.29 |
| ext4 (a clone, configured only) | 75.3 s | 333 s over 224 tests | 17.4 -- a concurrent build |

The per-check ratios are the ticket's shape (`target-pragmas` 15.5 s against 0.09 s), but the
WALL cost is about 17 s per pass, because the pass's critical path is `e2e-helpers-selftest`,
which is bound by its own sleeps rather than by I/O. The ext4 arm ran under a concurrent build and
the 9p arm did not, so the difference is if anything understated. It is accepted rather than
filed: the only remedy is building from a COPY of the sources, and a gate reporting on a copy
reopens the wrong-tree family this file enumerates, for a figure around one percent of a leg. The ext4
arm's 224 against 227 is a different configuration's test set, and its ten failures are tests
that need binaries a configure-only tree does not have; neither is a finding.

## What the TSan scope covers, and the three ways it has been wrong

<!-- agent-tripwire: The TSan scope is one Catch2 tag expression, in `tsan-gate.sh`'s `TARGETS` table, READ from there and never restated -->

The scope is **one Catch2 tag expression**, living in `scripts/tsan-gate.sh`'s `TARGETS`
table. `scripts/check-tsan-scope.cmake` **reads** it from there rather than restating it —
a second copy is not a cross-check, it is a second thing to be wrong, which is the rule
the section on that check's first draft already makes. `ctest -R tsan-scope-hygiene`, in
the **default** set, fails when a test CASE in a scoped location carries no tag that
expression selects.

Both halves of the scope have been wrong once, and the binary set was wrong for the whole
life of one binary. They are recorded together because they are three levels of the same
question — *what does this gate actually run under the sanitizer* — and each was invisible
from the level above it.

**The TAGS were wrong first.** Three of them looked complete and excluded six of ten
`Async/` files. That is what the check was written for.

**Then the SCOPE was wrong.** It named three directories. A `std::thread` census over
`PaceTest`'s own sources finds **nineteen** threaded files with **eleven** in no row
and under no tag — every threaded `Net/` test among them, which is `BlockingListener`'s
module and so the module the tree's one observed race (#260) came out of, reached only
because the node binary is run whole (#316).

So a row is now a directory **OR a FILE**, and *the file row IS the exemption mechanism*:
a mostly single-threaded directory is scoped one file at a time, so the check never forces
an unrelated tag onto a case. What it still cannot check is whether the table names every
threaded FILE. That census is a **proxy** — a helper spawns the thread, a comment names
one — so promoting it to a check would refuse correct files and miss incorrect ones. It is
left as a proxy deliberately, and said so here rather than left silent.

### The BINARY half is not a proxy, and it IS checked

`ctest -R tsan-binaries` ([#1209](https://github.com/LASTRADA-Software/pace/issues/1209)).
`pace-cc-tests` was in no row for its whole life and **no tag could have put it
there**: the launcher does not link the library, so it is a separate binary the other rows
cannot contain. A tag expression selects cases *within* the binaries the gate builds, and
says nothing about which binaries those are — which is why the level above could be
correct and complete while this one was neither.

The set is DERIVED from the `catch_discover_tests(` registrations, and each member is
either a `TARGETS` row or carries a **written exemption**. Three shapes are refused: an
empty reason, a row naming a binary nothing registers, and a row that is also a `TARGETS`
row.

**And an exemption's CLAIM is re-taken on every run, because a reason nobody re-measures
goes false in silence.** `pacectl-tests` stayed exempt as "single-threaded -- no
source names `std::thread`" after #134 gave it a thread pool and two suites asserting on
thread identities; the check went on passing, since a reason was only required to be
non-empty. So a row is `target|directory|reason`, and the check scans the directory for
the primitives in `PaceTsanThreadPrimitives` (`ThreadPoolExecutor` among them, which
is how this tree reaches a thread without spelling one), refusing a hit outside a comment,
a missing directory, and one holding no source.

That is the thread census the paragraph above declines to trust, used in the ONE direction
where its errors are cheap: a false positive refuses an exemption and costs a sanitized
binary that did not strictly need it, never a hidden race; a false negative -- a thread
spawned through a helper defined elsewhere -- leaves the row as unverified as it was
before. **A clean scan proves the written claim, not a single-threaded binary**, and the
refusal says so rather than letting a green run read as the stronger statement.

#1209's own hand census listed **four** test binaries where the tree registers **six**.
That is why this is a check and not a review item: the person writing the ticket, looking
directly at the thing, miscounted it.

Adding a row is **TWO edits** — the `TARGETS` table and the `clang-tsan` job's build step —
and the ticket's rule stands: **run the binary under TSan before adding its row**, or the
job goes red for the next person.

### And it proves a CASE, not a FILE

One selected tag ANYWHERE in a file used to cover every case in it. So a 28th case tagged
`[fleetchart]` in a file of 27 `[distributed]` ones left the sanitized scope with the check
reporting covered — the defect the file was written for, one level down
([#317](https://github.com/LASTRADA-Software/pace/issues/317)).

Reading a case's tags correctly is most of the work, and every part of it has a wrong
answer that looks right:

- A case's tag string is the **LAST** string literal of its header, never the second.
  Three cases here spell a long name as two adjacent literals, so "second" reads half a
  NAME as tags.
- **489 cases tree-wide carry NO tag string.** That is caught by ARITY rather than by
  pattern, because a name is free to contain `[async]` and must not talk its way in.
- A header may span lines — 28 in scope do — and may hold an unmatched `(` in a name, so
  the reader strips the literals **BEFORE** counting parenthesis depth. A reader that does
  not still closes a matched pair and passes such a case *for the wrong reason*, which is
  the failure mode that survives review.

Every way of losing the question is a **REFUSAL**: a header that never closes, one past a
line bound, a scope holding no case at all.

`scripts/check-tsan-scope-selftest.cmake` drives its cases over a tree staged from the REAL
scope table and copies of the REAL gate and root `CMakeLists.txt`. It `include()`s the
check for its table rather than keeping one.

That is ONE tree, staged once and restored after each case (#1423). A tree per case took
the test to 116 s of its 120 s on DrvFs under a gate's load. The shared tree has a hazard
the per-case trees did not: a change nobody recorded outlives its case, and a later write
to the same path hides it. So a case changes the tree only through helpers that record the
path, each helper first requires the path to be at its baseline, and the last case accepts
the restored tree. A leak is refused, never inherited. It is a sibling script rather than a `-D`
mode because that is what every other `cmake -P` check here does, and because
`check-selftest-registered` reads argument dispatch — a `-D` mode is invisible to it.

Ten mutations each redden exactly the case that names them. Reverting to file-level
matching reddens eleven and leaves the nine that cannot see the difference green.

### A workaround with an expiry date is WIRED to fire

Never written down where only its own file's reader will meet it.

The scope is a tag expression rather than `ctest -L` because `catch_discover_tests` exports
tags as labels only from Catch2 **3.8.0** (`ADD_TAGS_AS_LABELS`). This tree pins 3.6.0,
whose `extras/Catch.cmake` carries **zero** occurrences of it — measured, against
`catch_discover_tests`'s 11 in the same file as the positive control.

The reason lived in `tsan-gate.sh`'s header, which whoever bumps the CPM block never opens
([#312](https://github.com/LASTRADA-Software/pace/issues/312)). So
`check-tsan-scope.cmake` now READS the declared version and refuses past a **WATERMARK**.

The watermark is a **pinned CONDITION** and must not be made to track `CMakeLists.txt`:
point it at its own subject and the comparison becomes `x > x`, false forever, the tripwire
silently gone. That mutation is a self-test case, because it is the tidy that suggests
itself — the same shape as every other cleanup in this file that removed a guard while
looking like housekeeping.

The refusal also names what must survive the move regardless of where the scope ends up:
**a scope selecting NOTHING is a refusal**, since a typo runs zero cases while every other
signal says clean.

## A gate that fails CLOSED and UNCONDITIONALLY can sit for days

<!-- agent-tripwire: a gate that fails CLOSED and UNCONDITIONALLY can sit for days with nobody filing it -->

Every entry in *A retry makes every one of these disappear* is the gate reporting on the
WRONG TREE. This is the other shape, and it is not in that list: the gate refusing EVERY
tree, at its first leg, with a confidently worded false cause.

**A red gate reads as "my branch is bad", never as "the gate is broken."** So nobody files
it. [#1031](https://github.com/LASTRADA-Software/pace/issues/1031) shipped inside the
change that added the guard (#926) and stood for two days. `run_preset` read `$dir`, which
is `local` to `configure_reason` and unbound there, and the `*)` arm reported

```
the resolved C++ compiler IS  (a compiler cache)
```

**All THREE conditions are needed for that to be quiet:**

- `-u`, making the unbound expansion an error;
- the **ABSENCE of `-e`**, so the error killed only the command substitution's subshell and
  the caller carried on with `""`;
- a default arm that ACCEPTS the empty result.

Remove any one and it is a loud failure naming the variable. Two lanes hit it and worked
around it by hand before anybody suspected the instrument.

Its `none` arm had, on the evidence, **never once been observed answering**. Which is the
lesson the wrong-tree list does not carry and the reason this has its own section:

**A guard nobody has watched ACCEPT is not known to work.** Assert the passing direction,
not only the refusing one. The same sentence is made from the other side in
`.agent/rules/wire-and-protocol.md`, where `write-slot-guard-canary` drives an ordinary
sequential pair of writes and requires the acceptance marker before it double-arms.

## Which files are this project's own is ONE answer (#1370)

<!-- agent-tripwire: Which files are this project's own is ONE answer: `scripts/lib/third-party-roots.txt` -->

Importing `vendor/` for #134 needed **five** tree-wide enumerators told about it one at a
time -- `tidy-sweep.sh`, the header filter and the registration derivation in
`local-gate.sh`, `check-succeed-not-skip.cmake`, `check-target-file-guards.cmake` -- and
**three of the five were found by review** rather than by the import. Each answered *which
files are this project's own?* on its own, in its own grammar, and the default was the
dangerous one: an enumerator nobody had told INCLUDED the vendored tree, so upstream code
was linted, formatted, scanned and counted as first-party, silently and green. The census
that opened the work found more than five.

So the answer is data, in one place: `scripts/lib/third-party-roots.txt`, one root per
line, `#` comments, read by `third_party_roots` (bash 3.2) and `pace_third_party_roots`
(`cmake -P`). Both readers REFUSE a file that is missing, names no root, or names one with a
leading or trailing `/`, a `..` or a backslash -- read as empty, it would hand every vendored
file to every enumerator. `third-party-roots-selftest` drives both over the same files and
requires them to agree, because two readers of one format are two parsers.

- **An enumerator asks, and says what it declined.** `first_party_paths` /
  `third_party_paths` in `scripts/lib/third-party-roots.sh`, `pace_decline_third_party`
  in `CheckCommon.cmake`, then a line naming the count and the first declined path. A run
  that declines silently cannot be told from one that declined nothing.
- **It asks the tree it WALKS, not this repository** -- which is what lets each script's own
  self-test plant a roots file and a third-party path and watch the decline happen. Every
  migrated self-test has that case, and each was neutered to confirm it bites.
- **The set of enumerators is DERIVED.** `check-third-party-roots.cmake` holds what a
  tree-wide walk IS as a table of spellings with the rule beside each count, finds every
  site, and refuses one in a file that calls no reader. The readers it recognises are
  derived from the two libraries, and a CALL outside a comment is what counts: its first
  version accepted any mention of the file name, which a comment satisfies.
- **An exemption is a row with a REASON** (`third-party-roots-exemptions.txt`), and a row
  whose file no longer spells that walk is refused as stale. *Third-party code happens not
  to match* is not a reason: it is a bet on the world's layout.
- **A root is the upstream COPY, never the directory holding copies.** `vendor/monocypher`,
  not `vendor`: `VENDOR.md` and `MANIFEST` are written here, and a root
  of `vendor` answers *third-party* for this project's own build glue, dropping it from every
  scan that reads the file. The next import is its own row -- and the second was: `vendor/monocypher`
  (#178), beside `vendor/endo` until #1596 moved that code to core-cpp. The verbatim check and the figures check read the file too, so that row is also what
  hashes the copy into `vendor/MANIFEST` and asks `vendor/VENDOR.md` to describe it; a re-sync
  names ONE root (`PACE_VENDOR_RESYNC_ROOT`), so it cannot bless another copy's changes.
- **clang-format is the enumerator no script can make ask**, so each root is also a row of
  `.clang-format-ignore`, refused when missing -- and `local-gate.sh` compares the
  formatter's declined count with the offered files under the roots, both directions: fewer
  means vendored source was just rewritten, more means first-party files went unexamined.

**What it does NOT cover, stated so nobody reads it as more.** The answer is per FILE: a
script with one enumerator that asks and a second that does not passes, because following
data flow through shell variables is beyond any line reader here. The spellings are a model
narrower than bash, so a walk spelled another way (`ls -R`, a `**` glob, `find` over a root
variable with an unrecognised name) is not seen, and adding one is adding a row. Only
`scripts/`, `cmake/` and `.github/workflows/` are scanned -- a `CMakeLists.txt` globs from
its own directory -- and nothing checks an enumerator that is anchored under `src/`, which
is correct: an inclusion list naming this repository's own layout needs no roots.

## And HOW a file set is found is ONE answer too (#1485)

<!-- agent-tripwire: And HOW a file set is found is one answer too: `pace_tracked_files` -->

#1370 settled *which files are this project's own*. The sibling question — *how is a file
set obtained at all* — had **eight** answers, one per `check-*.cmake`, each a byte-identical
copy of a work-tree probe, an `ls-files` call, a `GLOB_RECURSE` fallback and
`set(excludeNames "out" "build" "_deps" ".git" ".cache" ".claude")`. Seven copies of that last
line, and an exclusion list is a bet on the world's layout: seven bets that have to move
together.

**What was shared is the MACHINERY; the file set is not shareable and must not be made so.**
That is the finding, and it is the opposite of what the ticket was filed saying. The eight ask
eight different questions — `*CMakeLists.txt`, `src/*.cpp src/*.hpp`, one subdirectory, the
test files by pathspec, every tracked C++ source, and one that does not enumerate at all — so
`pace_first_party_cxx` fit **none** of them verbatim and migrating any onto it would have
narrowed or widened what its rule is enforced over. Three of them and the first-party set both
answer **915** files today, which is a real coincidence rather than evidence they agree: every
one of this repository's own C++ files is under `src/` spelled `.cpp` or `.hpp`, and every
third-party file is under `vendor/`. It diverges the moment a `.h` or a `tools/*.cpp` appears,
and nothing would say so.

- **One function, parameterised by the question.** `pace_tracked_files(<dir>
  [PATHSPECS ...] GLOBS ... [FILTER ...] FILES_OUT v MODE_OUT v)`. The pathspec and the glob
  stay in the file where the rule is; `pace_first_party_cxx` is a CALLER of it, not the
  thing every check calls.
- **The pathspec and the glob are the same question twice, and the FILTER applies in both
  modes.** A filter living in the pathspec on one side and in the glob on the other passes
  every per-mode assertion while covering two different sets.
- **The fallback is gated on the MODE, never on the list being empty.** `if(NOT sourceFiles)`
  conflates *no mode answered* with *a mode answered and its filter kept nothing*, so a real
  git answer can be overwritten by a walk under a verdict naming the wrong mode.
- **`ls-files` succeeding and naming NOTHING is not the same event as there being no index**,
  and every copy reported the latter for both — a true-sounding sentence about the
  environment that is false. A walk therefore says WHICH of its two reasons it ran for.
- **But a fixture must not pin WHICH walk reason**, because that is a fact about where the
  scratch directory sits: a staged tree with no `.git` of its own is still inside a work tree
  whenever `CMAKE_CURRENT_BINARY_DIR` is, and it is — `out/build/...`. Every `baseline via
  walk` case asserts `directory walk` and the reasons are pinned where a fixture controls the
  probe. Measured: six of these were green with the scratch directory in `TEMP` and red with it
  in `out/`. In `check-catch-skip-selftest` that assertion is an ABSENCE, so the class-level
  string is also **stricter** — the old spelling passed with the third mode's string present.
- **The work-tree probe answers in THREE values**, `pace_work_tree_state` →
  `work-tree` / `no-git` / `not-a-work-tree`, because an enumeration walks the directory on
  either negative while a check with nothing to fall back on SKIPS, and owes an operator a
  different sentence for each. It also settled a disagreement the copies carried in silence:
  they compared the exit status `EQUAL 0`, `check-repository-hygiene.cmake` with
  `STREQUAL "0"`.
- **`check-repository-hygiene.cmake` has no file set and must never grow one.** Its subject is
  what the INDEX holds (`ls-files --error-unmatch` on named forbidden paths), which a directory
  walk cannot answer, so its probe ends in a SKIP where every other check's ends in a fallback.
  It shares the probe, nothing else.
- **A consolidation removes N chances of a silent miscount and ADDS one**, so the shared
  function has a self-test of its own (`tracked-files-selftest`, default set). Without it the
  risk has moved rather than gone: an over-broad enumeration reports on files a rule was never
  written for, an under-broad one reports clean over files it never read, and every downstream
  verdict stays green either way.
- **All three probe answers are REACHABLE by a fixture, and one took arranging.** A directory
  outside every repository is not something a staged tree can guarantee, so `not-a-work-tree`
  is arranged by asking about a repository's own `.git` DIRECTORY — which git answers `false`
  for while succeeding, and which is the state's own meaning rather than a trick.
- **`.ipp` and `.inl` are in the C++ extension set although this tree tracks none.** Measured:
  0, against 464 `.hpp` as a positive control on the same pattern. `check-ranges-seam` covered
  them before it migrated, so the extensions moved INTO the helper rather than the check
  adopting a narrower set: a difference that is invisible today and silent on the day it matters
  is worse than one that shows up as a count.

## `git grep` exits 0 over a file it cannot read; stderr is the only signal

<!-- agent-tripwire: untriaged: #1567 the git-grep-cannot-read rule has no AGENT.md bullet; one is proposed for the integration consolidation -->

**`git grep` exits 0 over a tracked file it cannot open**, leaves it out of `-l` and `-L`
both, and says so on stderr alone: `error: failed to stat 'X': Permission denied`.
Measured with git 2.53 on ext4 under `chmod 000` as a non-root user and git 2.51.2 on
Windows under a deny-read access list — the same status, the same line. It also skips a
tracked file DELETED from the work tree without a word, stderr included, and never searches
a symlink. Each of those is a file left out of an answer, and **a file left out of an
answer is a file PASSED**: the reviewer's plant, `::htonl(` in a `chmod 000`
`src/Pace/Core/Endian.hpp`, made the byte-order check exit 0 through the seam when the
per-file read it replaced had refused.

So `pace_tracked_files` (`scripts/lib/CheckCommon.cmake`) owes an ACCOUNT of every file
a question names — judged, reported missing, or refused by name — and the rules follow:

- **Any stderr makes a search untrusted**, a status of 0 included, and the question is then
  answered by reading every file. A benign line some git prints costs time and never a
  verdict — that direction fails CLOSED on purpose.
- **Unreadable is not missing.** A file that is there and cannot be read is refused whenever
  contents were asked for (`cannot judge a file it cannot read`) and is never MISSING_OUT's —
  a presence-only question answers "present", which is true. Deleted, or a link to nothing,
  is MISSING_OUT's answer when the caller asked, and refused otherwise.
- **The directory tells the two apart, not the file.** `EXISTS` is `access(R_OK)` on POSIX
  and calls a `chmod 000` file absent; `file(TIMESTAMP)` is empty for both; a literal
  `file(GLOB)` reads names out of the directory, so it lists an unreadable file and a
  dangling link and not a deleted file. A link is followed to the END of its chain (a cycle
  is nothing).
- **A walk refuses a directory it cannot list**: `file(GLOB_RECURSE)` skips one silently, so
  every file under it would go unfound. On POSIX the directory is still listed as an entry
  and `EXISTS` calls it absent.
- **Prove a plant bit with the primitive under test.** `cmake -E cat` exits 0 with no output
  over a file a Windows access list denies, so it reads as "readable"; the self-test asks a
  child `file(READ)` instead.

The same defect in a shell script is the same rule: `check-tidy-sweep-database.sh` kept
`2>/dev/null` on its `git grep`, and its walk's `grep -r` exit 2 vanished into a pipeline;
both now refuse on any stderr. Census pattern for the next one: `git( -C [^ ]+)? grep` over
`scripts/*.sh` and `scripts/*.cmake`. Enforced by `ctest -R tracked-files-selftest`, whose
unreadable rows run on Windows (access list) and on POSIX legs as non-root.

**Blind spot, and its direction.** On Windows neither `EXISTS` nor `IS_READABLE` sees an
access list and a glob has no error channel, so a deny-list DIRECTORY in a walk is still
skipped — **OPEN**. A deny-list FILE is caught in git mode by git's stderr naming it, and in
a walk by CMake's own failing `file(READ)`. The walk is the no-index case; CI's Windows legs
run in git mode.

## The enumerators of an enum are a view, and a hand-spelled walk is refused

<!-- agent-tripwire: An enum's ENUMERATORS are `Enumerators<Enum>()` / `Enumerators(from)`, never `views::iota` to `EnumeratorCount<Enum>` -->

`Core/EnumTable.hpp` offers `Enumerators<Enum>()` and `Enumerators(Enum from)` (#1441), and
`ctest -R enumerator-walks` refuses the hand-spelled form: `views::iota` to
`EnumeratorCount<Enum>` on one line, or a `for`/`while` bounded by it.

**The reason it needed a scan is that the hand-spelled form obeyed every existing rule.**
The guidelines forbid C-style loops and ask for range views; all ten sites #1441 converted
used `std::views::iota`, which IS a range view. The defect was walking INDICES to reach
ENUMERATORS — one site even cast the enumerator back out again, comparing
`static_cast<std::size_t>(route.match) != kind`, to meet the index it had been handed. No
loop-shape check can see that, so this is the second kind of guard: the one CALLED alongside
an operation rather than folded into it, which is the kind that needs a scan.

**What it deliberately does not refuse, because that was measured.** A `static_cast` near an
`EnumeratorCount` looks like the obvious third pattern and matches six sites in this tree —
`static_cast<std::size_t>(raw) >= EnumeratorCount<E>` in `Consensus/RaftTypes.hpp` and
`apps/pace-cc/Stats.cpp` — every one of which is a BOUNDS CHECK on a value off a wire
and correct. A check on it would refuse working code, which is why the loop shape requires
`for`/`while` on the line: `>=` is a range test and a `<` inside an `if` may be one too. Nor
does it cover a walk split across lines, or the C-style three-clause form, which is #1452's
scan — stated in the refusal itself so the next reader does not over-apply it.

The seam's own existence is the ANCHOR: with `Enumerators` gone from the header the check
REFUSES rather than reporting a clean tree, because *no violations* and *the rule no longer
applies* are different answers and only one of them is good news.

## A C-style loop is classified by its BODY, and "not a range-for" is not "stays a `for`"

<!-- agent-tripwire: A C-style loop is classified by its BODY; the head is not a classifier -->

#1452 converted the three-clause form across `src/`, and **the head is not a classifier.** Of
the 134 backlogged sites the opening estimate called 78 mechanical; 68 were, and nothing about a
head says which. It closed with `scripts/check-test-loops-backlog.txt` EMPTY: every site either
converted or moved to `PaceTestLoopExemptions` with the reason it stays.

Five shapes are not a RANGE-FOR, in the order they cost the most, each with the target it
actually took:

- **The body ADVANCES the loop variable**, to consume an escaped character, a continuation or a
  length prefix — `CompileCache/PathCanon.cpp`'s depfile tokenizer, `Protocol/RedisResp.cpp`'s
  `SET` options, `Cli/UsageTestUtils.hpp` and three walks in `apps/pace-cc/DirectManifest.cpp`.
  In a range-for that `++i` advances the ITERATION'S COPY, so the second character is consumed as
  data. Not a crash: in `DirectManifest` it mis-splits a dependency path on `\ `, which is **a
  wrong cache key**. **And `auto i` compiles silently** — only `auto const i` is refused, by
  `error: increment of read-only variable 'i'`, so the careful spelling is the one that fails
  loudly and the careless one ships. The target is a `while` with ONE advance at its foot and
  every `continue` inverted into an `else` of the arm before it — the shape `Cli/Options.hpp`'s
  `ParseOptionsInto` took first — so no path can skip the step and the head no longer advertises
  a constant one the loop does not take.
- **A CALLEE advances it through `std::size_t&`**, which no body scan can see:
  `Cli/Options.hpp` and `apps/pacectl/CliCommand.cpp` pass their index to `ApplyOneOption`,
  `Config/FileOptions.hpp` to `TakeValue`. Both consume an option's VALUE, so a conversion to a
  range-for makes every `--key value` flag re-read its value as the next token — across argv, the
  launcher's flags and the config-FILE appliers at once, silent for boolean flags. This is the
  shape that survives a careful reading of the loop. Two became `while`s; `CliCommand.cpp` stays,
  because its five `continue`s would each need the step.
- **A COMPOUND bound.** Two clauses are not one range — but they are often one range AND A BREAK.
  `std::min` where both clauses bound the index, and a `break` asked where the head asked it where
  the second clause is something else: on `Net/EpollSocket.cpp` / `Net/KqueueSocket.cpp`'s `iovec`
  batch builders it is a slot BUDGET that an empty segment does not spend, so it is checked BEFORE
  each segment, at the top of the body. Converting on the first clause alone overruns a write.
  *Measured* on those builders with g++ 14.3 and clang 22.1 at `-O2`: the code generated differs,
  and the range form is the shorter of the two in both (69 against 73 lines of assembly once
  directives are dropped under g++, 40 against 55 under clang). *Inferred*: neither difference
  can be seen beside the `sendmsg` that follows every batch.
  `Cache/CacheEngine.cpp`'s stream walks bounded on `out.size() < count` with `count == 0` meaning
  unbounded — which is a `take` after all, because `out` starts empty and gains one entry per step.
  One helper, `FirstCount`, CLAMPS the count to the match first: a client may send `COUNT` up to
  `UINT64_MAX`, and past `PTRDIFF_MAX` that is a negative `take`, which the view does not allow.
- **The induction variable OUTLIVES the loop** — `RedisResp.cpp`'s XCLAIM declares `i` above two
  sibling loops and the second RESUMES where the first `break`s, so neither converts in isolation
  and nothing in either head says so. Two phases over one cursor are two `while`s over a shared
  `i`.
- **Erase-while-walking**, which wants an ALGORITHM rather than a range-for. `std::erase_if` on a
  container is SPECIFIED as exactly the loop it replaces — each element visited once, in order,
  erased when the predicate answers true — so a predicate may do the per-bucket removal itself
  and answer whether that left the bucket empty (`PubSubRegistry`, `RedisTransaction`,
  `StreamWaiterRegistry`). A find-and-erase of one element is `ranges::find` and one `erase`
  (`Net/IocpSocket.cpp`, which cannot reach `Core/Ranges.hpp`'s `FindOrNull` across the
  `net-boundary`).

**An INCLUSIVE bound is on none of those lists.** `i <= N` is `iota(first, N + 1)` and a
DESCENDING loop is that range through `views::reverse`; what it needs is a stated premise — `N + 1`
cannot overflow, and the range is EMPTY where the loop ran zero times — rather than an exemption.
A STRIDE is a range over the group ORDINAL with the index derived from it (`Core/Base64.cpp`,
`Cluster/ClusterState.cpp`, `Distributed/FleetChart.cpp`, `Distributed/FleetHistory.cpp`), with the
count rounded up where the original stepped past a partial last group. Not `views::stride` or
`views::chunk`: they are C++23 adaptors of the family this tree already avoids for AppleClang's
libc++ (`enumerate`, `zip`), and nobody has measured them there.

**What stays a `for` is a sequence the standard library has no range for**, and it stays with an
exemption row naming why: a C linked list (`getaddrinfo`, `getifaddrs`, `GetAdaptersAddresses`), a
`directory_iterator` advanced by the error-code overload, a sentinel-terminated block, a
work-stealing index, a find-walk over text it rewrites, and a loop with no condition. Moving such
a loop's constant step from the head to the foot of a `while` buys nothing and costs a trap: the
next `continue` anybody writes skips it and never ends.

**Every one of these shapes was first classified mechanical**, by three successive versions of
the classifier — comments unstripped (a `;` inside `// … itself; drop it` truncated an unbraced
body), no inclusive verdict, no escaping verdict. They failed the same way each time, and that
direction is structural rather than unlucky: **a text scan fails toward "nothing unusual here",
so every gap in one lands in the bucket whose sites get converted without being read.** A
classifier for this therefore fails CLOSED and names the callee, and it refuses to print any
count until it reproduces a hand-read site per verdict — the figures are otherwise
unfalsifiable, and the first probe for inclusive bounds answered *0 sites* over an empty file
list with no control. **And the opposite error was made twice, too**: the inclusive bound, and
then four of these five, were first listed as NOT CONVERTIBLE when only the range-for had been
ruled out — an over-report that points sites at exemptions they do not need.

`std::views::iota` is the target, NOT the `Ranges::` seam — `check-ranges-seam.cmake` states it
is deliberately outside it. For argv, the target is `std::span<char* const>{argv, argc}.subspan(1)`,
because argv is the raw array `std::span` exists for and an `iota(1, argc)` still indexes a bare
pointer.

## An MSVC-style debug-info link is never incremental

<!-- agent-tripwire: No MSVC-style debug-info link is incremental -->

CMake links Debug and RelWithDebInfo with `/debug /INCREMENTAL` on an MSVC-style toolchain.
`cmake/IncrementalLink.cmake` rewrites the EXE, SHARED and MODULE linker flags of both to
`/INCREMENTAL:NO`, in one place, before any dependency or target exists, and
`ctest -R incremental-link` reads the GENERATED `build.ninja` rather than the module's word
for it (the configure-output rule above).

**What failed.** Five times on one Windows host on 2026-09-28, in two lanes' `cl-debug`
trees, the incremental relink of a test executable stopped with
`X.obj : fatal error LNK1163: invalid selection for COMDAT section 0x2F53`. Each time the
section was the vftable of a header-inline polymorphic test class, a pick-LARGEST COMDAT
that every including object declares identically, just after a header edit recompiled those
objects. A plain retry with nothing recompiled linked.

**The cause is INCONCLUSIVE, and the mitigation does not wait for it.** A standalone
reproduction with this tree's flags failed 0 times in 860 links: 250 each with no launcher, a
warm cache and a cold cache, and 110 with `/INCREMENTAL:NO`. Its control never failing means
it clears nothing and implicates nothing, so it is not evidence for either reading. Every tree
that failed builds through `pace-cc`, so *where* it happened cannot separate launcher from
linker. What a launcher-fronted tree differs in is two things. (i) The bytes a HIT restores:
measured identical to `cl`'s own apart from the one-byte COFF timestamp, and both failing
objects that could be placed were `cl`'s own MISS output. (ii) The `/Z7` that
`cmake/portable/CompileCache.cmake` forces. Neither is launcher CODE acting at link time; (ii)
is a configuration. What survives either reading is incremental-link state, and a link that
keeps no `.ilk` has none to go stale.

**So it is never gated on the launcher.** A gate there bets on the one reading the evidence
cannot make, and leaves `/Zi` plus `/INCREMENTAL` exposed, which was never tested. Two
spellings are not stacked: the module REMOVES every form of the switch and states one, because
which of two spellings wins is the linker's choice, and `/debug` with no switch at all links
incrementally by default.

**What it costs**, measured on the real `pace-node-tests` inputs (118 objects,
410 MB, copied out of an idle tree), with link 14.51.36252 on a host at 100% CPU and 9
interleaved pairs:

<!-- table-total: none -->
| link | wall time |
| --- | --- |
| `/INCREMENTAL:NO`, full | 1.6-2.5 s, median 1.7 s |
| `/INCREMENTAL`, one object changed | 0.3-2.7 s |

That is at most about a second per link, and each test executable stops carrying a ~200 MB
`.ilk`. These figures are conditions, not a constant: re-measure before citing them for a
different executable or host.

**clang-cl is covered by the same condition and is unaffected by it.** `MSVC` is true for cl
and clang-cl. clang-cl links through `lld-link`, which never links incrementally and accepts
`/INCREMENTAL:NO` silently (LLD 22.1.3, checked with `/debug`, alone and beside `/INCREMENTAL`).
A GNU-style driver on Windows spells no such switch and is left alone.

## clang-tidy's header filter is matched against the path a header was OPENED by, in every spelling

<!-- agent-tripwire: untriaged: #1567 the separator-agnostic header filter has no AGENT.md bullet; one is proposed for the integration consolidation -->

`HeaderFilterRegex` in `.clang-tidy` is matched against the path the preprocessor
OPENED a header by, and that path is spelled by the build, not by the repository. The
MSVC compile database spells its include directories with backslashes, so
`#include <tests/ScratchPath.hpp>` opens `D:\...\src/tests/ScratchPath.hpp` — a
backslashed include directory and a slashed `#include` name. **So every separator in
the filter is `[/\\]`**, and the filter names this repository's own roots and no
dependency location.

**Spelled with `/` alone, the filter matched no header on a Windows run and the run
still read clean.** Measured with clang-tidy 22.1.8 on Windows over
`ConsensusTier_test.cpp`, a naming violation planted in a header under `src/tests/` and
force-included through the backslashed include directory: 0 reports under the `/`-only
filter — all 20,891 warnings suppressed as non-user code — and 2 under `[/\\]`. The
same shape held on three more units. Nothing looked wrong, because the main file's
findings still came through.

**Two dimensions, each of which has already shipped a defect**, so a verdict is taken
in both: WHERE a checkout lives (#1040 — a pattern anchored on a directory name matched
CI's `.../pace/` and no lane worktree) and HOW its separators are spelled (the
above). The guard that existed read **363/363 under both the broken and the fixed
filter**, because it matched POSIX paths only — a guard that could not fail on the
defect in front of it.

- **One predicate, one table of spellings**: `scripts/lib/header-filter.sh` —
  `header_filter_match` (coverage: a header counts only if it is taken in EVERY
  spelling), `header_filter_reach` (a leak: a dependency or third-party header taken
  in ANY spelling is one, since a filter taking catch2 only when backslashed drowns a
  Windows sweep and no other), and `HeaderFilterSpellings` (`posix`, `windows`,
  `msvc`).
- **Two callers of it, for two reasons.** `ctest -R tidy-header-filter` asks at this
  checkout's real root on EVERY platform, Windows included, where `local-gate.sh` does
  not run; `local-gate.sh`'s coverage check asks the same predicate as the tidy
  sweep's PRECONDITION, with the vendored/first-party split and its untracked-root
  refusal. Neither may grow a private copy of the match.
- **What must stay OUT is derived, not listed**: `header_filter_dependency_paths` lays every
  `CPMAddPackage(NAME ...)` the tree declares out in both layouts (`_deps/<name>-src/`,
  `.cache/CPM/<name>/<hash>/`) and both header shapes (`src/<name>/`, `include/<name>/`),
  and a tree declaring none is refused — zero is a parser that found nothing. Tracked
  third-party headers come from `scripts/lib/third-party-roots.txt`.
- **A miss names its cause**: a header taken in one spelling and not another is
  reported with `(<spelling> spelling)`, and the gate then says *separator*, never
  *where this checkout lives* — the #1040 sentence would send the reader to the wrong
  fix. A header missed in every spelling carries no suffix.
- **The remedy is either separator, never a second copy of the pattern.** Two copies
  — one `/`, one `\` — still miss MSVC's mix, and the self-tests pin exactly that.

**Blind spot, and its direction.** Both callers model `llvm::Regex` with `grep -E`
(POSIX ERE, where a backslash inside a bracket is literal, as it is in clang-tidy) and
model *how a build opens a header* with three spellings. No registered check asks
clang-tidy itself; the agreement above was checked by hand. A construct the two
engines read differently, or a build that opens headers by a fourth spelling (a `\\?\`
long-path prefix, an 8.3 short name), fails **OPEN**: the check says covered while
clang-tidy discards. That is the reason to keep the filter to classes, alternation and
`.*`, and to add a spelling row when a build is found opening headers another way.

## Open work

<!-- agent-tripwire: none: deferred work, tracked as GitHub issues; AGENT.md tripwires rules, not residuals -->

- **[#1713](https://github.com/LASTRADA-Software/pace/issues/1713)** — the rename to Pace
  left two refusals that name the OLD spelling and read nothing under it: `pace-cc` and
  `pace-node` print one stderr line while any `FASTCACHE_*` variable is set
  (`Cli/RetiredEnvironment.hpp`), and the top-level configure fails on a cache holding a
  `FASTCACHED_*` entry (`cmake/RetiredOptions.cmake`, `ctest -R retired-cmake-options`).
  Both are removed in 0.8.0, with their exemption rows in `brand-leftovers`.
- **[#1591](https://github.com/LASTRADA-Software/pace/issues/1591)** — three sites
  now feed a listing through process substitution, and the other herestrings are NOT
  swept. 341 `<<<` sites exist under `scripts/` and nearly all take a line, a row or
  one file's text; what is open is an audit of the ones that can take a LISTING, each
  currently under the 64 KiB boundary and therefore silent, plus the scan that should
  refuse the next one — a rule stated only in the files that obey it reaches no file
  that does not. The issue names the candidate sites. It also wants the boundary
  itself pinned by a case, so the bash or platform that moves it is a red rather than
  a Windows leg that hangs with no diagnosis.

- **[#1631](https://github.com/LASTRADA-Software/pace/issues/1631)** — every
  per-file scan in `check-e2e-helpers.sh`, `procsub-reader-scan` among them, reads
  through an extractor ending in `|| true`, so a grep that fails on ONE file passes that
  file: #1630's shape, failing OPEN. The canary before each scan catches only a failure
  that empties every file. The house idiom across seven extractors, so it is a design
  change of its own rather than a line of PR #1600.

- **[#1567](https://github.com/LASTRADA-Software/pace/issues/1567)** — `## A correction is a search,
  not a recollection` has no `AGENT.md` tripwire. The nearest bullet is `testing.md`'s
  census rule, which this section itself calls borrowed, so the rule that a claim
  corrected in the places you REMEMBER writing it is not corrected fires in no session
  that does not open this file. Marked `untriaged:` and not `none:`, because `none`
  would claim the section needs no tripwire, and `ctest -R rulebook-tripwires` prints
  the count against this issue on every run. `## clang-tidy's header filter is matched
  against the path a header was OPENED by, in every spelling` and `` ## `git grep` exits 0
  over a file it cannot read; stderr is the only signal `` are in the same state until the
  integration consolidation adds their proposed bullets.

- **[#829](https://github.com/LASTRADA-Software/pace/issues/829)** — six
  contexts are still `Undecided` in `check-merge-queue-contexts.sh`'s binding table
  (`Windows-cl-debug`, `Code coverage`, both `compile-cache E2E` legs, the
  `pace-cc` smoke and `Docker image`). They cited #408, which the sanitizer
  promotion settles, so they were re-pointed at #829 in the same change: **an
  `Undecided` row naming a CLOSED issue is the "forgot" state the three spellings
  exist to keep distinguishable from a decision** — it still reads as *somebody will
  settle this*, the tally goes on printing it every run, and nobody owns it. The
  check asserts a row NAMES an issue and cannot tell an open one from a closed one,
  so nothing offline catches this; it was found by hand. `NotBinding` with a reason
  is a complete answer for most of these — a verdict is what is missing, not a
  promotion.
- **[#835](https://github.com/LASTRADA-Software/pace/issues/835)** — `clang-tsan`
  is the ONLY job in `build.yml` that sets `timeout-minutes`, so the jobs behind **twelve
  of the thirteen** required contexts inherit GitHub's 360-minute default. Raised while
  promoting the two sanitizer legs, and the survey is what stops it being filed as a
  regression from that: the promotion added two instances of a condition eleven required
  contexts were already in, and the likeliest leg to wedge is `clang-tidy`, the slowest in
  the workflow and required all along. The cost is **not** "six hours of held queue" — the
  ruleset's `check_response_timeout_minutes` is 60, so the entry is EJECTED at an hour
  (#359 already has) — it is an hour of queue latency plus up to six hours of runner time
  after the queue gave up. A bound needs measured durations: one set below a leg's real p99
  is a flake generator, and `clang-tsan`'s own 60 is a leg-specific argument about bounding
  its BUILD rather than a house number to copy.
- **[#830](https://github.com/LASTRADA-Software/pace/issues/830)** — nothing
  stops the required set or its count being restated in prose again. There is no
  drift today; what is missing is the guard, and the obvious one was measured against
  the tree and rejected rather than skipped. The measurement and the alternatives it
  rules out are on the ticket, and the rule it enforces is the
  *neither-the-set-nor-its-count* bullet above.
- **[#717](https://github.com/LASTRADA-Software/pace/issues/717)** — the
  open-or-update-an-issue decision exists twice: `scripts/ci-report-issue.sh`,
  which `merge-group-report-selftest` drives against a stub `gh`, and the inline
  copy in `build.yml`'s clang-tidy job. Deliberately not folded together as part
  of #684: that step is inside a REQUIRED context and is reachable only on a
  master push whose sweep has already failed, so editing its YAML to remove a
  duplication risks every lane's pull request for no gain #684 needs.
- **[#858](https://github.com/LASTRADA-Software/pace/issues/858)** — the eleven
    translation units no analyser sees are GATED but still unanalysed. #682 is CLOSED:
    #857 measures the set, refuses in both directions and pins the configuration in its
    verdict, so a unit going blind can no longer pass unnoticed. What remains is giving
    them an analyser — six Iocp need a Windows tidy leg, five kqueue a macOS one — and
    the caution that made #682 sit still applies: the ticket's fifteen pre-existing
    diagnostics would land a permanently RED context, a worse instrument than the gap,
    and neither leg can be developed from a Linux host.
- **[#1234](https://github.com/LASTRADA-Software/pace/issues/1234)** —
  `PreprocessArgv` still parses the whole compile database once per translation
  unit: 14.1 s of CPU a sweep against 141 ms batched, ~0.3% of wall clock. #605
  closed the CORRECTNESS half and deliberately left this one. The plan now hands
  over the entry's own `file` string as a third column and the lookup matches it
  exactly and verbatim, so `PreprocessArgv` consumes what `PlanUnits` produced
  rather than holding a second, looser rule (`endswith`) for a question `PlanUnits`
  already answered — where the two disagreed the looser one won silently,
  classifying a unit from a command that is not its own. The row is split on a
  FIXED field count that refuses anything else by name, because `${unit#*$'	'}`
  strips through the **first** tab and folded any third column into `$file`.
  **Not `IFS=$'	' read`**: a tab is IFS whitespace, so an empty field collapses
  and shifts every field after it, and the empty-`file` row would read as a short
  row and pass. What is left is the parse, and its route is blocked on a smaller
  question — `TidyOne` hands ONE directory to both `clang-tidy -p` and
  `PreprocessArgv`, so making every unit a single-entry database also changes which
  database the ANALYSER reads. A batched pass is accepted only on identical
  classifications over the real database — a 100× speedup that moves one verdict
  is a regression, because the verdicts are the entire job. The method is settled:
  compare the two rules as a LOOKUP rather than by compiling every unit, which #605
  did at 566 of 566 identical, with a control proving the comparison could see a
  difference.
- **[#607](https://github.com/LASTRADA-Software/pace/issues/607)** — #568 made the
  two CMake sites agree on the lookup that RUNS the interpreter, and `cmake/Coverage.cmake`
  names the four places python is located and which two do not validate. **Nothing reads
  that comment.** A third `find_program(NAMES python3)` passes every check in the tree and
  the comment goes false silently, which is #568's own divergence one level up. A check
  would be a glob over `**/*.cmake` and `**/CMakeLists.txt` and never a file list (#492),
  a general needle rather than the exact line removed, and it must express
  `cmake/Version.cmake` as a REASONED exception — its `find_program` for git is
  deliberate, because the module is included before `project()` where `find_package` has
  no toolchain — or the check fails a correct file. Roughly 3x the diff it protects, so it
  is recorded rather than urgent.
- **[#311](https://github.com/LASTRADA-Software/pace/issues/311)** — nothing in
  CI catches an uninitialised read, and no sanitizer that runs today can: ASan does
  not, UBSan does not, and neither does ThreadSanitizer. That is MemorySanitizer,
  which needs an instrumented standard library, or valgrind memcheck over the
  existing release test binaries. It is the other half of #132, deliberately left
  out of the TSan job rather than folded into it.
  **The instrumented-standard-library clause is now MEASURED rather than assessed**
  (`scripts/probes/msan-uninstrumented-libstdcxx.sh`, 2026-09-11, clang++-22 against
  gcc 14's `libstdc++.so.6`). MSan is live on this toolchain — a plain uninitialised
  read reports — and the split it produces is the part a smaller probe gets wrong:
  header-only use is CLEAN, because `vector`, `string`'s inline members and
  `to_string` are instantiated into instrumented code, while `ostringstream`,
  `locale`, `filesystem` and throwing an exception each report a
  use-of-uninitialized-value INSIDE `libstdc++.so.6` on a program that has none.
  Every Catch2 binary reaches the second set on every run, so an MSan job reports
  about the standard library before it can report about this tree. `libc++` is no
  escape and fails EARLIER — its `basic_string::__is_long` is out of line, so even
  the header-only arm reports there. Three drafts of that probe were silent for
  reasons that had nothing to do with libstdc++ (`-O1` folded the read away; a
  store to `volatile` is not a use MSan reports), which is why it refuses when its
  own control does not fire. Not measured, and the next thing to measure: whether
  the tree reports under an MSan build with every dependency built from source —
  this build additionally links `libyaml-cpp.so.0.8`, `libssl.so.3` and
  `libcrypto.so.3` as system shared objects, of which TLS can be turned off and
  yaml-cpp can be forced from source. valgrind was absent on the machine that took
  these readings; apt offers 1:3.22.0-0ubuntu3, and that route needs no rebuild.
- **[#1272](https://github.com/LASTRADA-Software/pace/issues/1272)** —
  `scripts/check-gate-target-set.cmake` compares the local gate's
  `gate_target_flags` against every `-DPACE_BUILD_*=ON` the workflow passes
  ANYWHERE, and deliberately does not model which jobs run `ctest`: deriving *this
  job tests* from the YAML is fragile in the direction that fails SILENT, where a
  job whose test step is conditional or renamed reads as "does not test" and the
  check quietly stops covering a target set CI really exercises. Failing closed
  inverts that. The stated consequence is that a job turning one of those flags on
  WITHOUT running tests makes the check refuse a correct tree — no such job exists
  today, and when one appears the answer is a decision (exempt the job by name with
  a reason, model the testing jobs, or narrow the subject) rather than a fix. It is
  recorded before it fires because the natural response to that refusal will be
  *the check is broken*, and it will not be: a red gate reads as "my branch is bad"
  rather than as an instrument asking a question nobody has answered yet.
