# Changelog

## [Unreleased]

> Everything below is on `main` but has not shipped as a numbered release:
> `VERSION` and the npm package both still read `2.2.0`.

### June 2026 backfill (38 commits, `cf626d0^..d9a4369`)

These landed between 2026-05-29 and 2026-06-20 and went unrecorded at the time.
Folded by theme rather than commit-by-commit; key SHAs are given so the detail
stays diggable.

**Onboarding rework** — reshaped the first run around one intake prompt, one
hard-boundary question call and a single queue gate.

- Streamlined the guarded first-run flow (`983da60`) and reworked terminal
  presentation and progress cues (`2314478`).
- Selection entry, resume-only intake and function-relevance gating (`c4ae787`),
  with the `target_function_anchor` producer wired so long-tail functions get
  deterministic gating (`d8eb424`).
- Missing-info questions are now derived from the real applications and
  condensed (`a29e6db`), then ranked by how many jobs each answer unlocks
  (`bb31bf7`) — instead of asking a fixed list per application.
- Grounded cover letters generated for auto-apply (`590c75a`).
- New supporting skills: materials, expand, upskill (`9196a95`); liveness
  reports and outcome analysis (`5acee6b`).

**Apply-path fixes** — the bulk of the month, mostly Greenhouse and Ashby field
coverage found by real submissions.

- Unblocked storage plus Ashby phone/remote/city auto-answers (`555d797`);
  open-ended residence, work-style, major, graduation and sponsorship phrasings
  (`2b5f6ad`).
- Greenhouse: profile-backed residence facts (`6436b26`), Faire profile-backed
  fields (`89443d1`), work-environment preference (`1073dac`), templated text
  fields (`b6c30f7`), profile-backed followup routing (`9cb2873`).
- Ask-and-retry on missing-info gaps (`b434e8d`), reuse of already-answered
  profile facts (`c5f2894`), common ATS blocker fields (`dd7a8e5`).
- Bad queue rows filtered and availability inferred (`0d1dd8b`); complete scoring
  enforced before store (`ef2f682`); default batch cap removed (`4dcf2e1`).
- Tolerant radio-choice matching for relocation questions (`73e061f`).
- Reliable React form-fill, combobox Enter handling and batch resilience
  (`5f4d2ff`).
- Lever added to the stable batch path (`1aaa94c`). Note that Lever is still
  outside `SUPPORTED_AUTO_PLATFORMS`; see `docs/ARCHITECTURE.md`.

**Packaging and public alpha** — public alpha release gate (`cf626d0`), repo
prepared for demo release (`20ef503`), npx entrypoint (`a8404da`), one-line
install surfaced in the README (`96da9a5`), landing page simplified (`89233c6`),
jobskill live entrypoint (`dd468ba`), README banner and badges (`d9a4369`).

**CI and tests** — the node test suite runs serially (`b581936`) after parallel
runs proved flaky through shared temp artifacts; onboard temp artifacts isolated
(`71a2ff9`); onboard skill kept under the alpha gate (`d328087`); local scratch
dirs ignored (`618cb04`).

**Docs** — v3 PRD and engineering backlog captured (`50bab4c`). That PRD has
since shipped and now lives in `docs/archive/`; the current one is
`docs/PRD-improvements.md`.

### Fixed
- **Nothing is dispatched without passing the ledger-backed pre-dispatch
  gate** (2026-09-25, restart-apply S2). `apply_batch` re-reads the ledger
  before every row and calls `apply_guard.checkDispatch`: already attempted
  (same fingerprint, or same company + title), company attempted twice in 60
  days, today's tier used up (10/25/50, local calendar day; above 30 needs
  `--confirm-tier-over-30`), or a job that already failed before Submit more
  than `PRE_SUBMIT_RETRIES_60D` times → not dispatched. "Attempted" means one
  thing everywhere: ledger `may_have_submitted === true`. An in-flight marker
  (`locks/inflight.json`) makes a crash between driver and recorder get
  recorded on the next run instead of re-applied; three identical machine
  failures in a row stop the batch. `daily_count.jsonl` is no longer written.
- **A re-application is no longer relabelled as a skip** (2026-09-25). The
  recorder's post-submit duplicate check used to mark a real submission
  `⚠️ 跳过未投` while the ledger said submitted. It now reads the ledger,
  records the truth, and exits 1 with `invariant_violation_reapplied`.
- **Ledger lines carry their own job identity** (2026-09-25, restart-apply S1,
  permanent format). Every line now has `apply_url` (must yield a
  platform:job-id fingerprint) and `may_have_submitted` (derived once, in
  `driver_contract.deriveMayHaveSubmitted`: exits read-verified to fire before
  the first Submit click are `false`, everything else `true`).
  `node shared/submission_ledger.mjs backfill-legacy [--apply]` migrates the
  legacy jobs.db history (default dry-run, idempotent, count-checked).
- **essay_pending.jsonl no longer stores form answers** (2026-09-25). Both
  drivers wrote the whole record, answers included; they now drop `answers`
  (the ledger keeps them) and the file is in `PII_TARGETS` (600).
- **An unreadable Ashby API answer no longer kills a live job** (2026-09-25).
  A 200 without a `jobs` array used to read as an empty board, so liveness
  marked live postings expired; it now throws (`ashby_unexpected_shape`) and
  liveness says `uncertain`. Each request also has a 15 s timeout.
- **Form answers no longer leak into jobs.db** (2026-09-25, restart-apply
  小修包, 第 7 轮验收 P2). `record_apply_outcome.mjs` wrote the whole driver
  outcome — including every answer typed onto the form, work-authorization
  answers among them — into `feedback.detail` of the world-readable jobs.db
  and into the manual-review file. Answers now go to the 600 ledger only;
  every DB / manual-review write uses a copy without them.
- **Liveness can finally tell a dead Ashby posting from a live one**
  (2026-09-25). Ashby pages are client-rendered, always HTTP 200 and all embed
  `recaptchaPublicSiteKey`, so live, taken-down and made-up postings all read
  as the non-blocking `bot_challenge`. `jobs.ashbyhq.com` rows are now checked
  against Ashby's public posting API: ID on the board → `live`, not on it or
  board gone → `expired`, API unreachable / no ID in the URL → `uncertain`
  (never blocks). One board fetch per company per batch.
- **Ashby rows whose form never loaded no longer loop forever** (2026-09-25).
  Two exits in the Ashby driver still printed the legacy `skip`, which the
  recorder refuses, so the row was never recorded and got re-picked every
  batch. Both now go through the contract as `crashed`; a source guard fails
  the tests if any driver prints a bare outcome line again.
- **`demo:check` no longer reports "ready rows: 0" on macOS** (2026-09-25).
  `supervisor_preflight --json` exited right after printing >64KB; macOS pipes
  are asynchronous, so the parent got 65536 bytes, failed to parse, and showed
  0. Preflight and demo:check now set `process.exitCode` and let stdout drain;
  unreadable preflight output is a failing check with `ready_rows: null`, not 0.
- **"How many did I apply to" now has one answer instead of three**
  (2026-07-30, 阶段 1「数字变真」包 2). The DB carried three submission cells
  giving three different totals (158 / 182 / 183). A new append-only ledger
  (`~/.mrweirdo-jobs/log/submissions.jsonl`) is the single authority for "did
  it go out": every attempt — succeeded, refused, crashed — is one line with
  the page verdict, evidence paths and **every answer typed onto the form**;
  the only writer is `record_apply_outcome.mjs`; corrections are appended with
  evidence, never edited in place; `node shared/submission_ledger.mjs rebuild`
  recomputes the DB cache from the ledger (dry-run by default, idempotent with
  `--apply`), and preflight fails hard if the cache diverges from the ledger.
  Every counting read point (dashboard, queue, diagnostics, report) now uses
  the one exported predicate — same copy of the DB prints 182 everywhere.
- **Drivers exit through one contract; no path defaults to success**
  (2026-07-30, ADR-15). Seven outcome words (`submitted` / `not_submitted` /
  `needs_user` / `captcha_blocked` / `rate_limited` / `crashed` / `unknown`)
  with fixed exit codes (0/2/2/3/4/1/2); `outcome:"submitted"` is refused
  unless backed by the page-level verdict; a driver that dies without output
  is recorded as `crashed` and highlighted in the batch summary instead of
  filed as a routine skip; legacy words (`skip`/`essay_pending`/`error`) are
  loudly rejected, not silently aliased. Ashby/Greenhouse now stop on the
  first attempt when the page states failure with nothing fillable (the
  Directive pages used to burn four blind retries); Greenhouse's and Lever's
  local success regexes are gone — the shared verdict judges everything.
- **The dashboard's daily quota no longer shrinks when a submission gets
  confirmed** (2026-07-30). The today-count only recognized `✅ 已投`, so a row
  confirmed the same day silently left the daily-cap math — loosening the
  anti-blacklist limit. It now counts through the same single predicate.
- **Negated success copy, nested screenshot dirs, and two half-built helpers'
  poison branch** (2026-07-30, 第 6 轮验收三条扣分项). "was **not**
  successfully submitted" is now a deny rule (it used to judge `submitted`);
  the PII sweep descends into already-locked subdirectories; jobvite/icims
  helpers no longer treat "thank you for your interest" — the literal text of
  the Directive failure banner — as a success signal.
- **A page saying "We couldn't submit your application" can no longer be
  recorded as a success** (2026-07-30, 阶段 1「数字变真」包 1). The Ashby
  driver's success regex had an `already applied…` branch that judged that
  exact failure banner as submitted — six historical screenshots named
  `success` show that banner (all six re-opened and transcribed as regression
  fixtures). "Was it submitted" now has a single implementation
  (`shared/submission_evidence.mjs`): confirm/deny rule tables, all rules
  consulted, both-or-neither → `unknown`, and `unknown` never counts as
  submitted. Every rule ships with a fixture the tests verify it fires on.
- **Evidence file names are decided by the judged verdict, and screenshots are
  full-page** (2026-07-30). Names used to be bash-assembled in skill docs
  before anyone read the page — that is how failure pages got named
  `success`. Now one command reads, judges, then shoots the whole page
  (single-viewport shots caught the mid-form answers in 2 of 50 historical
  screenshots); files are named `…_after_<verdict>.png` and born locked.
- **Personal-data files are locked where they are written, with a pre-batch
  sweep for the ones nothing produces** (2026-07-30). One carrier list
  (`shared/state_file_lock.mjs`) covers profile files, resume, cover letters,
  screenshots and the batch transit files that hold real form answers; the
  screenshot funnel, the cover-letter writer and the batch runner lock at the
  write, preflight sweeps before every real batch, and `demo:check` observes
  without touching (report-only mode) so a diagnostic never mutates the home.
- **The pre-batch gate now asks "was he ever asked", not "is the cell filled
  in"** (2026-07-30). The old predicate assumed a student needs his work permit
  before applying; the truth runs the other way (offer first, then the school
  approves the permit — 关卡 7), so a normal F-1 student who answered every
  question he can answer was locked out of every batch forever. Measured on 72
  real submissions: the missing cells actually block 4/72 = 5.6% of rows while
  the gate blocked 100%. The gate now closes exactly once — for a profile the
  identity funnel never touched — and unanswerable cells stop only the rows
  that really ask that question, with the rest applying as normal.
- **"Don't answer this for me" is no longer treated as "never asked"**
  (2026-07-30). Q4's default answer gets its own note and lands on a self-serve
  list (job link, materials ready, he fills the last cell himself) instead of
  re-opening a question he already answered; switching his policy to "fill
  yes/no" later re-queues those rows automatically.
- **The visa-status field no longer reaches employers, verbatim or inferred**
  (2026-07-30, ADR-12). It used to be rendered word-for-word into the
  availability answer (five of 73 real submissions carried that sentence,
  including branches that would have shipped the user's own Chinese words onto
  an English form), and five driver branches plus one answer bucket regex-matched
  it into Yes/No claims — a profile holding a Chinese sentence was answered "No"
  to "Have you been admitted to the US as a nonimmigrant?". Employer-facing text
  now reads the three-state booleans only (null = the clause does not appear),
  the field is a five-value enum the write-back command enforces, and a
  read-point whitelist test turns any new unregistered reader red.
- **A fact he had already answered stopped being asked over and over**
  (2026-07-26). The fix above reads the custom-facts bucket one fact at a time,
  but it was only wired into the two paths that name a bucket up front. The
  bucket's main entrance is the catch-all at the end of the classifier — the
  bucket is defined as "facts with no bucket of their own", which is exactly
  what reaches that line — and it never looked at the profile at all. Measured
  against the real profile's eleven answered facts: eight of ten probes were
  asked again anyway, `us_citizen` among them, which he had answered `false`.
  Three of those were also handed a key of their own alongside the one already
  in the bucket (`rate_your_excel_proficiency` beside `excel_proficiency`), so
  answering as instructed would have written a duplicate and asked again next
  run. Now two of ten, both of them keys written by hand rather than published
  by the report; answering either once under the published key ends it for good.
- **The concierge refusal now leads with the action that fixes the machine**
  (2026-07-26). The likeliest way to meet this message is the note outliving the
  run — the runbook deletes the sandbox first — and the message opened by
  telling the owner to re-run against that deleted sandbox. "Delete the note"
  was the sixth line, in English, under a Node stack trace that reads as a crash
  to someone who does not program. It now opens with a copy-paste `rm`, in
  Chinese, printed plainly with exit code 3 instead of an uncaught throw, and a
  test holds the Node and shell wordings identical — all four of them as of
  2026-07-26 (the locked home, plus the three ways a sandbox can find its note
  gone). That test first built only the locked-home case, so a one-character
  change to any of the other three passed the whole suite; it is now
  parameterised, and each of the four was proved to go red on its own. The note
  also gained its missing half: the sandbox carries a marker naming the home that left the note,
  and both entrances refuse a sandbox whose note has gone missing or points
  somewhere else — before this, forgetting the note or deleting it early turned
  the entire protection off with no sign at all. A run that skips the setup step
  outright still cannot be detected, and the runbook says so — as of 2026-07-26
  under step 1 itself, spelling out what a skipped step 1 costs, rather than in
  a limitations list at the very end that a reader reaches after the damage. The
  "stop at step 4" boundary is stated at step 4 for the same reason.
- **A question nobody was ever asked no longer comes back as "the profile has
  it"** (2026-07-26). The catch-all "unknown fact" bucket counted itself
  answered whenever `standard_qa.custom_facts` held anything at all. The real
  profile holds eleven entries, so the rule added the day before — "the driver
  reported it had nothing to type, so do not claim the profile holds it" — was
  cancelled out for the only real user: the row stayed stuck, silently, exactly
  as before. The bucket is now read one fact at a time, the way the location
  rule already read one city at a time: a form label is turned into the key its
  answer is written under, and only a key matching that label counts as an
  answer. The report publishes that key next to each question, so answering it
  actually ends it — left to whoever writes the answer, a fresh key would be
  invented each round and the same question would come back forever. Measured
  on the real profile: 14 of 40 probed cells move from "fill it from the
  profile" to "ask him", every one of them a cell where the driver had already
  said it had nothing to type; the 26 cells without such a report are
  byte-identical.
- **Running someone else's resume on this machine can no longer leak into the
  owner's home** (2026-07-26). Two holes. Run artefacts — the scored job list,
  what each form was actually filled with, which personal questions went
  unanswered — defaulted to a shared `/tmp/mrweirdo-onboard` reachable only
  through a second switch that no skill and no script ever set: moving
  `MRWEIRDO_HOME` moved the profile, the resume and the database and left all of
  that behind, world-readable, for the next run to read back as its own. They
  now default to `<home>/run-tmp`, so one switch moves everything, and the skill
  docs stop hard-coding the old path. The second hole was not code: the
  isolation rides on environment variables, which do not survive from one bash
  block to the next, so a single un-prefixed block wrote a stranger's data into
  the owner's home without a word. A run now marks the owner's home with
  `.concierge_run_active`, and both `atsHome()` and the shell entry points
  (`scripts/concierge_guard.sh`, for the ones that copy the resume with `cp` and
  never reach Node) refuse that home while the marker is there, naming the
  sandbox the run belongs in. Nothing under `/tmp/mrweirdo-onboard` was moved or
  deleted. Operator instructions: `docs/active/2026-07-26_concierge-run_RUNBOOK.md`.
- **Onboarding asks what kind of person you are, not whether you are authorized
  to work** (2026-07-26). The old question was one four-option pick with CPT/OPT
  in the option text, and it asked the user to reach a legal conclusion about
  himself — for an F-1 student that conclusion depends on the role, his school
  and the timing, so nobody can answer it reliably, and a wrong answer hurts
  both ways (saying "yes" is a misstatement on a real employer's form; a citizen
  saying "no" is filtered out on the spot). It is now three yes/no questions
  about facts a person can read off his own documents — citizen or green card /
  F-1 student / has the work permission come through (the EAD card, or the CPT
  line on the I-20) — with the four profile fields derived in code by the new
  `shared/work_auth_identity.mjs`. The module writes only the cells it can
  actually determine: an F-1 student whose permission has not come through gets
  `requires_sponsorship_future: true` and **nothing** written to
  `authorized_to_work_us`, because `false` there is byte-identical to "he said
  no" and gets him rejected outright. "I can't tell" is now a supported answer
  rather than a dead end: the pre-batch gate hands back what it is stuck on,
  three concrete places that hold the answer (the school's international student
  office, page 2 of the I-20, the EAD card) and the promise that the queue keeps,
  and it marks the batch so nobody is asked the same unanswerable question twice.
- **An Ashby question with no text box no longer disappears** (2026-07-26).
  A blocked question only reached the pending list when the driver could point at
  a `textarea`/`input[type=text]`; work authorization, sponsorship and residence
  are dropdowns and radios on a real Ashby form, so question and reason both
  vanished, leaving one bare label in `missing` and a row stuck for no stated
  reason. The selector is now optional (it is for typing the answer back, not
  for deciding whether to ask), and the pending list dedupes on the question —
  Ashby re-generates the field id on every submit attempt, so the old
  (question, selector) key let the same question through repeatedly.
- **"The profile was empty" now beats a label rule that says "fill it from the
  profile"** (2026-07-26). Drivers append the form's own label to some notes
  (`value_empty_for:what is your gpa?`, `no_bucket_for:…`), so the report's
  exact-match note table could never hold them and every one of them fell back
  to guessing from the form's wording — the same guess that filed a blocked
  residence question as "the agent fills this". A prefix rule now rules out that
  one verdict while leaving the specific bucket to the label rules, so a GPA
  stays `user_gpa` with its own question and write path. Ashby's
  `relocation_commitment_policy_unset` joined the exact table, and the
  "has the profile answered this" test for location became per city: he agreed
  to the Bay Area, which says nothing about Denver, and treating it as an answer
  is how a question about a city he never named turned into a silently stuck row.
- **The shipped template no longer claims a 3.9 GPA for the user** (2026-07-26).
  `shared/profile.template.json` shipped `education.gpa: "3.9"` — a fact about
  the user's grades nobody stated. Measured against the shipped Greenhouse
  driver: a factory profile asked "What is your GPA?" typed `3.9` onto the form.
  It is also truthy, and `apply_gap_report.mjs:266` reads any truthy value as
  "the profile knows this", so the question was filed under *fill it from the
  profile* and the user was never asked. It now ships empty: the Greenhouse
  driver blocks the field (nothing typed — not `0`, not `""`), Lever leaves it
  unresolved, and the report files it as `user_gpa`, a question with an existing
  write-back path. A user who did state a GPA still gets exactly that GPA typed.
  Same disease and same treatment as work authorization, demographics and
  relocation; GPA is named in the same red line and was the last name on it
  still shipping a value.
- **An Ashby application that stops on an unknown fact now says why**
  (2026-07-26). The driver returns a precise reason (`specific_city_fact_unconfirmed`,
  `work_authorization_required`, …) with each blocked question, but the pending
  list dropped it, keeping only question/selector/tag. The gap report then had
  to guess from the form's own wording: "Do you currently live in the San
  Francisco Bay Area?" matched its `currently live` label rule and landed in
  `agent_profile_backed` — *do not ask the user, fill from the profile* — for a
  profile holding no such fact. The row was blocked and the user was never
  asked. The pending entry now carries the driver's note (one line, no new
  lines); the same question is now routed to `user_logistics_fact` and becomes a
  real question. Work authorization was unaffected either way — the report has a
  label rule for it; residence, transport and legal facts had no such net. The
  Ashby driver has a test harness now, built the same way as the Greenhouse one.
- **A fresh install no longer agrees to relocate on the user's behalf**
  (2026-07-26). Asked "Would you be willing to relocate to our New York
  office?", six profile shapes were fed to the shipped Greenhouse driver: five
  surfaced the question to the user, and the factory template answered `Yes`.
  Two template values each reached it on their own —
  `standard_qa.willing_to_relocate_scope: "Anywhere US"` and
  `target_filters.relocation_policy: "anywhere_primary_country"`, both of which
  resolve to the driver's `anywhere_us` alias. Both now ship empty, along with
  `standard_qa.willing_to_relocate`. Same rule as the work-authorization block:
  a factory value is byte-for-byte what a real answer looks like, so nothing
  downstream can tell "the user agreed to move" from "nobody ever asked".
  Relocation is named in the red line itself and was the last name on that list
  with no assertion behind it; it has one now, including an end-to-end guard
  that drives the shipped driver. A user who did state a relocation scope is
  still answered from their own words.
- **`secure_profile_files.sh` now locks the optional files it was meant to**
  (2026-07-26). The optional-file loop sat after the required-file loop, which
  exits on the first file it cannot find — and `answer_provenance.json` exists
  from the answer write-back while `search_intent.json` is not written until a
  later onboarding step, so the block never ran in the window it was added for.
  Measured: `answer_provenance.json` left at 644. The optional loop now runs
  first; a missing required file is still a hard exit 1. The script had no test
  beyond a syntax check and now has one.
- **Main entry no longer dies on its first command** (2026-07-25). All 9 bash
  blocks in `.claude/skills/mrweirdo-onboard/SKILL.md` did `cd "$MRWEIRDO_REPO_ROOT"`
  while nothing ever set that variable: `cd ""` returns 0 without changing
  directory, so the first command "succeeded" silently and the next one died
  with a bare `No such file or directory` (exit 127) for anyone who did not
  happen to start in the repo directory. Each block now resolves
  `MRWEIRDO_HOME`/`MRWEIRDO_REPO_ROOT` itself with the same `${VAR:-default}`
  form the 8 single-URL skills already used. The same unguarded `cd` was also
  fixed in `mrweirdo-ashby-auto`, `mrweirdo-greenhouse-auto`, `mrweirdo-tracker`,
  `mrweirdo-expand` and `mrweirdo-upskill` (11 more blocks) — the auto engines
  are dispatched during a real batch, so they were on the same main chain.
- **The tool no longer answers factual questions about the user it was never
  told the answer to** (2026-07-25). Work authorization and future sponsorship
  are three-state facts (yes / no / never asked), but `deriveWorkAuthAnswers()`
  read them with a truthy check, so "no" and "never asked" both fell through to
  the answer-bank defaults — which shipped as `Yes` for both. A user who had
  explicitly recorded "not authorized to work in the US" still got `Yes` typed
  onto a live form, and a user needing no sponsorship was made to claim they
  need it. Now: `true` → Yes, `false` → No, missing → the row blocks as a
  user-answer gap (`work_authorization_required` / `sponsorship_future_required`)
  and the answer bank is not consulted for these two personal facts at all.
- **Greenhouse now obeys that same rule — the 88% of the queue that the first
  pass missed** (2026-07-25). The first pass fixed the shared decision function
  and wired it into the Ashby driver only; `shared/greenhouse_apply_driver.mjs`
  kept answering "Are you legally authorized to work in the US?" from
  `BANK.yes_no_defaults.work_authorization` (`Yes`) and the sponsorship question
  from `BANK.yes_no_defaults.sponsorship_future` (`Yes`), reading neither from the
  profile. Measured on the eligible-but-unapplied queue, 256 of 292 rows are
  Greenhouse. `answerMissing()` now runs the same `workAuthGapFor()` guard before
  it answers anything, both value branches read `deriveWorkAuthAnswers()`, and the
  "will you require future immigration support" branch blocks instead of falling
  back to the bank. Real-run check across 6 profile shapes: before the fix all 6
  answered `Yes` to every work-auth question; after it, "not authorized" answers
  `No`, a citizen answers "no sponsorship needed", and the three never-asked
  shapes fill nothing and surface the row as a user-answer gap.
- **A blocked row now turns into a question instead of a silent retry loop**
  (2026-07-25). The drivers were stopping correctly, but nothing downstream
  listened. `collectFields()` pushed `b.question` — a plain string — so the
  driver's `note` was dropped, and the surviving label then hit a catch-all
  regex that filed work authorization, sponsorship and every EEO question under
  `agent_profile_backed`, whose instruction reads *"do not ask the user, fill
  from the existing profile"*. The profile held nothing to fill from, so the row
  was retried, blocked again, and re-filed — with the user only ever seeing
  "skipped". Now the whole blocker object is carried, a 16-entry note→category
  table (each note verified to be emitted only when the profile is empty) runs
  before the label regex, work-auth and EEO are profile-backed only when the
  profile really holds the value, and the three new `user_*` categories are in
  `RETRYABLE_CATEGORIES` so answering actually re-queues the rows. The note
  lookup deliberately reads `field.note` and not the row-level `outcome.reason`:
  three row reasons share a spelling with field notes, and the fallback would
  have labelled a GPA question a legal attestation.
- **Answers now reach the profile through a command, not an instruction**
  (2026-07-25). `SKILL.md` said "after the user answers, update the local profile
  as needed" — a request aimed at a language model. `shared/record_profile_answers.mjs`
  replaces it: it can only write paths that some question declares (the whitelist
  is derived from `QUESTION_TEMPLATES`, so what we ask and what we may write
  cannot drift apart), it checks types instead of coercing them (`"true"` is not
  `true` when the subject is someone's work authorization), and it either updates
  the profile completely or leaves it byte-identical. A companion
  `answer_provenance.json` (chmod 600, fingerprints only, never values) records
  where each answer came from; per ADR-4 it never affects form filling.
- **A batch refuses to start while work authorization is unanswered**
  (2026-07-25). One gate, one fact, on a measured rule: a fact earns a pre-batch
  gate when its absence blocks 80%+ of rows, and today only
  `authorized_to_work_us` and `requires_sponsorship_future` qualify. Everything
  else still waits for a real form to ask. It is a hard `supervisor_preflight`
  check rather than a warning — this file already emits five kinds of warning
  and an automated flow walks past all of them — and `--dry-run` surfaces the
  same gap in `profile_gate` so the queue gate can raise it while the user is
  still reading the queue.
- **The profile template stops answering work-authorization questions on the
  user's behalf** (2026-07-25). `authorized_to_work_us: true`,
  `requires_sponsorship_now: false`, `requires_sponsorship_future: true` and a
  placeholder `visa_status` shipped in every install. A pre-filled `true` is
  byte-for-byte what a real answer looks like, so the three-state guards added
  earlier this week could never fire for anyone who started from the template.
  All four now ship empty, with a `_notes` line explaining why, matching
  `legal_attestations` and `demographics`. `validate_user_profile.mjs` already
  accepted null, so no validator change was needed.
- **The work-auth guard no longer fires on "advisable"** (`shared/answer_routing.mjs`):
  the label pattern used a bare `visa`, which matches inside `ad-visa-ble`. It is
  now `\bvisas?\b`. (A company literally named "Visa" still matches — there
  "visa" really is a word. Unchanged, and it only over-asks, never over-answers.)
- **Master's-degree question reads the profile** (`shared/greenhouse_apply_driver.mjs`):
  it was hard-coded to `No`. It now uses `isGraduateDegreeProfile()`, whose
  matching moved to the unit-tested `isGraduateDegree()` in
  `shared/greenhouse_value_rules.mjs` and is word-anchored — the old unanchored
  pattern read "ms" out of "Information Systems" and "ma" out of "Marketing".
- **Veteran status defaults to declining, like the other EEO questions**
  (`answer_bank.json`, both drivers' fallback banks, Ashby + Lever): the default
  was the factual claim "I am not a protected veteran" while gender, race,
  orientation and disability all correctly declined. `shared/profile.template.json`
  now ships `demographics` as nulls — pre-filled values were byte-identical to a
  real user answer, so no code could tell "the user said this" from "the factory
  set this".
- **Regression guards for all of the above**: `test/answer_routing.test.mjs`
  covers the false / missing branches (previously only `true` was covered, which
  is why this shipped green), plus a constant-function assertion; new
  `test/personal_facts_guard.test.mjs` locks the EEO refusal defaults, the empty
  demographics template and the master's-degree source line. New
  `test/greenhouse_work_auth_driver.test.mjs` runs the shipped Greenhouse driver
  itself (only the six browser-boundary functions are stubbed) against six
  profile shapes, so the fill/block outcome is asserted on real driver code, not
  on a re-implementation of it.
- **Lever flow hardened for batch driving** (verified live 2026-05-28 by 5 real
  submitted Lever internships: everbridge, ekimetrics, endpointclinical,
  voltus, get-vocal). In `shared/lever_helpers.js`: (1) `waitForResumeStorageId`
  default 15 s → **45 s** (a slow form, everbridge, took ~35 s to assign the
  backend storage ID); (2) `findEmptyRequired` now also sweeps Lever custom
  "card" questions (`name="cards[uuid][fieldN]"` radios / native selects / text)
  that the `label[for=id]` sweeps missed — the gap that forced manual
  radio-filling — reporting each unfilled required control with its options;
  (3) new `Lever.fillCardField(nameOrId, value)` answers a card field reliably
  (radios/checkboxes via `<label>` click — React-safe; selects by option text;
  text via native setter).
- **Lever resume upload no longer false-skips on a bogus "File exceeds 100MB"
  error** (HANDOFF dragon #6). Root cause was timing, not a real rejection:
  Lever's upload is a slow two-step async flow — `cdp.mjs upload`
  (`DOM.setFileInputFiles`) drops the file and fires the native `change`, then
  Lever POSTs it to its backend and only *afterwards* writes `resumeStorageId`.
  Live boards take ~4–8 s (ekimetrics, field-ai, pyka, everbridge measured
  2026-05-28 — everbridge took 5.16 s). The old `waitForResumeStorageId`
  default of 5000 ms raced the backend; on a timeout the caller then read the
  hidden `.resume-upload-oversize` / `.error-message` template (a baked-in
  "File exceeds the maximum upload size of 100MB" element, never a real
  rejection on a 116 KB PDF) and skipped a perfectly good row.
  Fix, all in `shared/lever_helpers.js`:
  - `waitForResumeStorageId` default timeout raised 5 s → 15 s.
  - New `Lever.verifyResumeUploaded()` — the authoritative attach check, using
    only real-success signals (`resumeStorageId` non-empty, the visible
    `.resume-upload-success` "Success!" label, and the `has-file` button),
    never the hidden oversize template.
  - `isErrorMessageVisible()` now suppresses any "100MB"/oversize text once the
    upload has succeeded, so the benign template can no longer read as a real
    error. Verified end-to-end on four live Lever boards: resume attaches and
    shows "Success!" with a real backend storage ID; no submission was made.

### Changed
- Extracted the Ashby driver's answer-bucket matching DECISION into a pure
  `shared/answer_buckets.mjs` (`matchAnswerBucket(label, ctx)` +
  `buildAnswerBuckets`) — **verbatim** with the prior inline `buckets` array and
  `buckets.find(b => b.match.test(ml))` in `answerMissing()`. Every regex,
  action, value, choice, fallback and the `relocationCommitment` flag are moved
  unchanged; the values that referenced driver-scope variables (`linkedin`,
  `cityFull`, `compensationExpectation`, `sponsorAns`, `authorizedAns`, `rtoAns`,
  `PNA`, EEO answers, profile fields) are supplied via a `ctx` object the driver
  builds from PROFILE/BANK/SEARCH_INTENT (reusing `deriveWorkAuthAnswers`). The
  driver still performs all CDP eval/click/fill on the returned descriptor — only
  the decision is relocated, so the verified live path is byte-for-byte the same.
  Also extracted the post-SQL queue filter into a pure
  `passesQueueFilters(row, {roleTypes, submittedKeys, seenKeys})` in
  `shared/eligibility.mjs`, now used by `shared/auto_apply_queue.mjs`.
  Added `test/answer_buckets.test.mjs`, `test/answer_buckets_fixtures.test.mjs`
  (+ `test/fixtures/ashby_questions.json` of real Ashby phrasings) and
  `test/queue_filters.test.mjs`. Parity verified: `recompute --json` `by_reason`
  and `auto_apply_queue` row output are byte-identical before/after. Suite: 31 → 51.
- Extracted the safety-critical answer-routing decisions
  (`shared/answer_routing.mjs`) and the auto-apply eligibility gate
  (`shared/eligibility.mjs`) into pure, importable modules — **verbatim** with
  the prior inline logic — so they can be unit-tested without a browser tab or
  a SQLite database. `ashby_apply_driver.mjs` and
  `recompute_auto_apply_eligibility.mjs` now import them; `recompute --json`
  produces an identical `by_reason` breakdown (behavior parity verified).
  Added `test/answer_routing.test.mjs` (real abby-care / fuel-cycle labels +
  F-1 work-auth honesty: an OPT user answers Yes/Yes, never a false
  "no sponsorship") and `test/eligibility.test.mjs` (full-time-leak gate,
  role-type-checked-before-fit ordering, double-submit guard). Suite: 18 → 31.

## [2.2.0] - 2026-05-28 — Supervisor stack, discovery, role-type targeting, safety hardening, and the first regression harness

### Added
- Regression test harness using Node's built-in `node --test` (zero deps):
  `test/*.test.mjs` locks the role-type gate (full-time-leak prevention +
  `roleTypeConflict`), dedup normalization (double-submit guard),
  answer-template rendering (incl. honest F-1 future-sponsorship), and
  `answer_bank`/`essay_profile.template` JSON shape + regex validity. Added a
  GitHub Actions CI workflow (`.github/workflows/ci.yml`) that runs the suite,
  the role-guard smoke test, and a `node --check` of every shared module on
  push/PR. Run locally with `npm test` / `npm run test:smoke`.
- Added first-class `role_type_targets` support for internship, part-time,
  and new-grad/full-time boundaries.
- Added `shared/role_types.mjs` as the shared role classifier used by
  discovery hard-filtering and auto-apply queue selection.
- Added `shared/auto_apply_queue.mjs` so batch dispatch uses one reusable,
  target-role-aware queue instead of duplicated inline SQL.
- Added `shared/discover_candidates.mjs`, a reusable discovery + hard-filter
  wrapper with a no-network `--plan` mode and a `--run` mode that writes
  `/tmp/mrweirdo-onboard/to_score.json` for main-agent scoring.
- Added `shared/supervisor_status.mjs`, a one-command local snapshot for CDP,
  queue, capacity, latest report, DB status counts, and next safe commands.
- Added `shared/apply_report.mjs` to generate a local-only HTML
  "Mr. Weirdo Jobs Application Report" after a run.
- Added `shared/recompute_auto_apply_eligibility.mjs` so existing local
  databases can be repaired after threshold or role-type calibration changes.
- Added `shared/supervisor_preflight.mjs`, a no-submit gate that checks
  profile assets, role targets, queue validation, smoke tests, and CDP before
  a batch opens any ATS pages.
- Added `shared/apply_supervisor.mjs`, a single local CLI entrypoint that
  runs no-submit validation with `--dry-run` or, with explicit `--real`,
  verifies/launches Chrome CDP before delegating to the foreground batch
  runner.
- Added `shared/apply_batch.mjs`, a foreground supervisor runner that ties
  preflight, queueing, per-row validation, driver execution, evidence-bound
  recording, pacing, and report generation into one auditable command.
- Added `shared/queue_diagnostics.mjs` so a batch shortfall explains whether
  the blocker is low fit score, unsupported ATS, quota, role boundary, or
  duplicate submitted rows.
- Added local HTML queue review and capacity-plan reports so a requested
  100-application run shows ready-now rows, fit-one-below rescore candidates,
  unsupported ATS candidates, and remaining sourcing need.
- Added `shared/rescore_review.mjs` so fit-one-below candidates can be
  exported for human review and only selected IDs can be promoted into the
  auto-apply threshold.
- Added `shared/record_apply_outcome.mjs`, an evidence-bound recorder that
  updates `jobs.db` only after parsing the driver's final structured outcome.
- Added generic answer-template rendering so public `answer_bank.json` can use
  profile placeholders instead of shipping one student's personal essay text.
- Added `shared/essay_profile.template.json` and updated `/mrweirdo-onboard`
  so first-run intake is resume + short self-introduction + three
  hard-boundary questions, producing reusable private essay/cover-letter
  writing memory at `~/.mrweirdo-jobs/essay_profile.json`.
- Added `scripts/role_guard_smoke.mjs` to lock the Internship / Part-time /
  Full-time boundaries and stale-queue duplicate guard in a repeatable check.
- Public-facing docs now consistently reserve "Mr. Weirdo Jobs" as the
  project brand, while keeping `mrweirdo-jobs` as the repo/command slug.
- `.gitignore` now protects common local user-state artifacts if someone
  accidentally places them inside the repo tree.

### Fixed
- Auto-apply queue selection now requires `auto_apply_eligible=1`, target
  role type, supported ATS, no quota guard, and `fit_score >= 5`.
- `/mrweirdo-onboard` now treats part-time as distinct from internship and
  full-time instead of collapsing everything into `intern/new_grad_FT/both`.
- `/mrweirdo-onboard` now recomputes stale `auto_apply_eligible` flags before
  queue selection, so old `fit>=5` internship rows are not silently ignored.
- Final auto-row validation now rechecks role type from the title and blocks
  same-company/same-title rows that have already been submitted.
- `/mrweirdo-onboard` no longer documents unconditional `✅ 已投` writes;
  submitted status now goes through the recorder and requires
  `outcome="submitted"` from the driver.
- `/mrweirdo-onboard` no longer front-loads a seven-question onboarding form;
  softer preferences are inferred from the student's self-introduction and
  asked later only when they block real jobs.
- Supervisor preflight now warns when the requested batch size is larger than
  the currently eligible queue, so a "run 100" request cannot silently process
  only a small leftover pool.
- Supervisor preflight and the Chrome CDP launcher now print concrete recovery
  commands when Chrome CDP is missing, the default port is occupied by a
  non-CDP Chrome, or a sandboxed agent cannot open a GUI Chrome process.
- Greenhouse dogfood fixes now cover semester-only graduation date dropdowns,
  hidden policy acknowledgements, retired job redirects, embedded Greenhouse
  iframes, non-resume supplemental file guards, and compensation fallback text.
- Scorer prompt (`shared/scoring/score_prompt.md`) now hard-caps role-type
  mismatches: a role whose `role_type_match` is outside the user's
  `role_type_targets` must score `seniority_match <= 2` and `fit_score <= 4`,
  not `seniority_match: 10`. Defense-in-depth behind the eligibility gate so
  full-time roles can no longer *read* as a fit≥5 for an intern-only seeker
  (root cause of the 2026-05-27 full-time leak, verified gate-blocked
  2026-05-28).
- `shared/ashby_apply_driver.mjs`: added profile-derived buckets for the
  ubiquitous Ashby name fields (Legal/Preferred First/Last Name) so they no
  longer fall through to `no_bucket_for` / main-agent pending.
- `shared/ashby_apply_driver.mjs`: "How did you hear about this job?" is now
  filled as free text first (it is frequently a `textarea`, occasionally a
  radio group or react-select combobox) instead of being forced through the
  radio-multichoice handler — which previously matched a *false* container and
  could click an unrelated radio (e.g. a sponsorship option). Both fixes were
  verified by real submissions on 2026-05-28 (acorns Growth PM Intern, lambda
  Accounting AI Intern, both Ashby, confirmation pages captured).
- Known follow-up (logged, not yet fixed): numeric "What are your salary
  requirements?" fields (`input[type=number]`) reject the neutral
  `compensation_expectations` sentence and loop. The driver should detect a
  numeric comp field and emit `salary_number_required` when no user-authorized
  figure exists, instead of retrying. Surfaced by fuel-cycle row (skipped, not
  fabricated).
- Closed the role-type gate's title-trust hole: `shared/role_types.mjs` adds
  `roleTypeConflict(job)`, which flags an intern/co-op-titled role whose
  `employment_type` looks permanent (`FullTime`/`Permanent`/`Regular`) with no
  intern/temp/contract/seasonal signal — the ambiguous case worth a human
  glance. Title still wins (a real full-time-HOURS internship like a 12-week
  program is NOT blocked); the conflict is surfaced, not silently trusted.
  `shared/discover_candidates.mjs` annotates such candidates (`bot_note`) and
  counts `role_type_conflicts` in the discovery summary. Eligibility behavior
  unchanged.
- `shared/ashby_apply_driver.mjs` no longer silently commits the user to a
  SPECIFIC city. General relocation/onsite *willingness* is still auto-answered
  when `relocation_policy === 'anywhere_legal_work'`, but specific-city
  *logistics facts* — "reliable transportation to our <City> office?", "do you
  currently live/reside in/near <City>?" — now return
  `specific_city_fact_unconfirmed` (ask-or-skip) unless the city is in
  `factual_gap_fields.onsite_location_logistics.confirmed_cities`. New
  `onsite_location_logistics` taxonomy entry added to
  `shared/essay_profile.template.json`.
- `/mrweirdo-onboard` Step 10 now (a) surfaces the queued company/role list for
  visibility/confirmation before a `--real` batch submits anything (no
  application goes out under the user's identity to an unseen company), and
  (b) fills impactful OPTIONAL essays ("why do you want to work here", cover
  letters) from `essay_profile.json` instead of skipping them — especially for
  `fit_score >= 7` rows — keeping the never-fabricate guardrail.

### Added
- Added a `factual_gap_fields` taxonomy to `shared/essay_profile.template.json`
  documenting the recurring non-inferable fields ATS forms require — permanent
  address, social handles, compensation acceptance, third-party/game accounts,
  personal preferences/opinions, and a separate cover-letter file. These are
  ask-or-skip (never invented); `/mrweirdo-onboard` should surface unknown ones
  upfront so the auto-apply loop stops re-stalling mid-application on the same
  classes of question (observed on skipped rows 190/197/625).

## [2.1.7] - 2026-05-27 — Fit threshold calibration

### Changed
- Auto-apply now follows the recall-first calibration: `fit_score >= 5`
  is eligible.
- `/mrweirdo-onboard` Step 8 and Step 10 now use threshold 5 instead
  of 7. Dedupe, quota, supported-platform, and status guards still
  apply, so this increases recall without allowing duplicate or
  unsupported submissions.
- The scorer's `recommended` definition and profile template
  `min_fit_score` now match the same threshold.

## [2.1.6] - 2026-05-27 — Upfront relocation questionnaire

### Changed
- `/mrweirdo-onboard` now asks the core intent questions before
  generating `profile.json` / `search_intent.json`, instead of waiting
  until after resume parsing. Location and relocation constraints become
  first-class input, not late-stage apply blockers.
- A3 is now a structured geographic / relocation policy question with
  options for fixed local search, named metros, anywhere in the US, or
  multiple legally workable countries/regions.
- `profile.json` and `search_intent.json` now carry
  `relocation_policy`, `countries_open_to`, and
  `willing_to_relocate_for_internship` so discovery, scoring, and ATS
  form answers use the same boundary.

### Fixed
- Greenhouse location-specific questions now read the structured
  relocation policy. A user who explicitly says "anywhere in the US"
  or lists multiple workable countries/regions can truthfully answer
  yes to Austin-style internship relocation questions, while
  location-restricted users still block.

## [2.1.5] - 2026-05-27 — Controlled 3-row test follow-up

### Field results
- Controlled test attempted 3 rows after v2.1.4: Alpine row 477 and
  Cloudflare rows 244/248. No new submission was verified, so the run
  stopped before burning more Cloudflare attempts.
- Alpine exposed GPA / sourcing essay / Austin relocation / EEO and
  hear-about checkbox gaps.
- Cloudflare rows showed v2.1.4 progress: hear-about, sponsorship,
  privacy, university enrollment, degree, essay, and full-time timing
  filled; remaining blockers were Austin residency/confirmed plans and
  graduation-date select matching.

### Fixed
- Greenhouse graduation date answers now normalize `MM/YYYY` and
  `YYYY-MM` profile values to `Month YYYY` for select controls.
- Greenhouse location gating now recognizes `resident`, `based there`,
  and `confirmed plans` wording, so city-specific questions are treated
  as profile/user-answer blockers instead of being retried blindly.
- Greenhouse react-select lookup now uses `document.getElementById`
  and assigns synthetic IDs to unlabeled sibling inputs, avoiding
  selector syntax errors on EEO/dropdown fields.

## [2.1.4] - 2026-05-27 — Duplicate guard and Greenhouse postmortem fixes

This patch is a direct response to the first public-beta-style 10-row
apply run, which produced 1 verified submission and exposed repeat
queueing plus several Greenhouse form gaps.

### Added
- `shared/dedupe_jobs.mjs`, an idempotent jobs.db guard that marks
  duplicate pending rows as skipped by normalized company + title before
  the auto-apply queue is selected.
- Feedback-table audit rows for duplicate skips so repeat prevention is
  visible in local history.

### Fixed
- `/mrweirdo-onboard` Step 10 now runs the duplicate guard before queue
  selection, enforces the fit≥5 threshold at queue time, and ranks only
  one row per company/title fingerprint.
- Greenhouse success detection now accepts `/confirmation` pages with
  Greenhouse's "Thank you for your interest / next steps email" copy,
  which prevents real confirmations from being misclassified as
  `no_errors_no_success`.
- Greenhouse custom-field handling now covers common school, degree,
  major/discipline, project/portfolio URL, employer/title, graduation
  date, and earliest-start-date fields.
- Greenhouse location-specific questions are more conservative: the
  driver no longer answers city-specific onsite/relocation/enrollment
  questions when the city is outside the user's profile/search intent.

### Field notes
- The 10-row run had one verified submission (`attentive` row 432).
  Most failures were not caused by CDP itself; they clustered around
  unsupported custom questions, non-standard Greenhouse landing pages
  with no file input, and location/profile-specific requirements.

## [2.1.3] - 2026-05-27 — Public beta readiness pass

This release tightens the first-user path so the project can be tested
by real students without immediately falling into avoidable setup or
risk-boundary failures.

### Added
- `shared/doctor.mjs`, a local install/runtime readiness checker for
  Node 24, git, Chrome, Skill links, user-state files, and optional
  Chrome CDP connectivity.
- `/mrweirdo-doctor`, a non-submitting Skill wrapper around the doctor
  script for users who ask "can I use it now?" or need install help.
- Codex UI metadata (`agents/openai.yaml`) for the main onboard and
  doctor skills.

### Changed
- `setup.sh` now runs the install doctor and tells first-time users to
  start the dedicated Chrome CDP window before onboarding.
- `/mrweirdo-onboard` now launches Chrome CDP when missing, runs the
  doctor pre-flight, and gives a clearer recovery path.
- Chrome CDP tooling now supports alternate ports via `ATS_CDP_PORT`
  and records the active host in `~/.mrweirdo-jobs/cdp_host`; the CDP
  CLI and drivers read that host automatically.
- `shared/chrome-cdp-launcher.sh` now falls back to launching the Chrome
  binary directly if macOS `open -na` fails.
- Public beta auto-submit is capped at 10 rows per run by default.
  Maintainers can raise it deliberately with `MRWEIRDO_MAX_AUTO_APPLY`.
- Lever remains discoverable/scored but is excluded from stable batch
  auto-submit until the CDP upload issue is fixed.
- Discovery audit fields now preserve each row's real source instead of
  labeling every job as `remoteok`.
- README and DISCLAIMER now align on sources, timing, caps, Lever
  stability, and the optional nature of Notion.

## [2.1.2] - 2026-05-27 — Productize Skill packaging for Claude Code + Codex

This release starts turning Mr. Weirdo Jobs from prototype into a
cleaner, installable Skill collection for both Claude Code and Codex.

### Changed
- `setup.sh` now links the tracked `.claude/skills/*` source into
  Claude Code (`~/.claude/skills`), Codex user skills
  (`~/.codex/skills`), and a generated workspace-local
  `.agents/skills` mirror for Codex desktop.
- `.agents/` is now explicitly gitignored and treated as generated
  compatibility output rather than a second source of truth.
- `setup.sh` symlink collision handling is conservative by default:
  existing links/files are skipped unless `MRWEIRDO_FORCE_LINK=1` is set.
- README positioning now reflects v2.1.1 field reality: Greenhouse/Ashby
  are the best-tested auto-submit path, Lever remains experimental, and
  SQLite is the source of truth while Notion is an optional review mirror.
- Skill docs use more host-neutral wording ("main agent session") and
  clarify the onboarding contract: resume + questionnaire + parse
  confirmation first, then no per-application approval for supported
  auto-submit rows.

### Notes
- The canonical tracked Skill source is still `.claude/skills/*`.
  A future refactor can move it to `skills/*` and make both `.claude`
  and `.agents` pure symlink mirrors.

## [2.1.1] - 2026-05-26 — Directive ack cracked, GH Country verified, essay loop proved

Field follow-up to v2.1.0. This release turns the highest-leverage
unknowns from the handoff into verified behavior: Directive's ack widget
is no longer blocking, Cloudflare's Greenhouse Country select submitted
successfully, and the main-Claude-in-loop essay path processed real
pending rows to submission.

### Field results
- Directive Ashby rows `304-311` moved from
  `directive_still_blocked_after_essay_fill` to `✅ 已投`.
- Cloudflare Greenhouse row `247` submitted successfully; the Country
  sync-select path is verified in the field.
- Six Ashby `essay_pending` rows submitted after main-Claude-authored
  answers were added to the answer bank: `166`, `235`, `345`, `682`,
  `716`, `719`.

### Added
- New answer-bank templates for Base Power-style "good fit", N1, Ready,
  Julius, Blumen GIS, and Chai essay prompts.
- Work-term availability preferences in `shared/answer_bank.json`.

### Fixed
- Directive's "Please confirm..." ack is handled as a single-option
  radio, not as an Ashby Yes/No hidden-checkbox widget.
- Ashby native radio/checkbox choices now use the browser's native
  `checked` setter plus `input`/`change` events, which fixed Chai and
  Julius radio state not sticking in React.
- Ashby location, LinkedIn, portfolio/website, university, degree,
  graduation date, and start-date text fields use the smallest matching
  question container instead of accidentally climbing to the whole form.
- Ashby sponsorship wording is split: current internship work
  authorization can answer "no employer sponsorship" while explicit
  "now or in the future" sponsorship questions still answer truthfully.
- Greenhouse Cloudflare custom fields now cover Country sync-select,
  relocation wording, graduation date, full-time offer timing, and the
  privacy checkbox.

### Known limitations
- Base Power row `122` still needs a specific date-picker/auth-combobox
  fix. The correct auth choice is CPT/OPT, not the first option containing
  "Yes" ("U.S. citizen or permanent resident").
- The essay consumer is proven as a main-Claude-in-loop workflow via
  `answer_bank.json` + driver reruns, but not yet packaged as its own
  standalone CLI/skill.

## [2.1.0] - 2026-05-26 — Submit-error-driven drivers, 80% Ashby success in field

The big shift in v2.1 is architectural: instead of pre-emptively filling
every field before clicking Submit (v2.0's `fillForm` model), the new
drivers fill what they can, hit Submit, parse the form's own validation
errors, look up answers in an externalized JSON bank, and retry. This
turned out to be far more resilient to per-tenant form variance.

Field test today (2026-05-26): 23 Ashby submissions in one session via
the new driver, 1 GH submission via its GH sibling. ~80% Ashby success
rate; the failures clustered on a single ack-widget pattern (see Known
limitations) rather than scattering across form shapes.

### Added
- `shared/ashby_apply_driver.mjs` — submit-error-driven Ashby form
  driver. Submits → parses validation errors → looks up answers in
  `shared/answer_bank.json` → retries. Up to 4 retry rounds. Closes
  the tab on submit/skip. 80% success rate in today's field test
  (23/29 Ashby URLs landed; 6 skipped with explicit `skip_reason`).
- `shared/greenhouse_apply_driver.mjs` — GH equivalent. Same retry
  loop, plus react-select handling for Country + Location combobox.
  Newer than the Ashby driver, less battle-tested (1 submit so far).
- `shared/answer_bank.json` — externalized answer templates: 7 essay
  patterns, Yes/No defaults, multichoice prefs. Users edit this file
  directly; no code change needed when form shapes drift.
- `Ashby.clickAckWidget()` in `shared/ashby_helpers.js` — 5-strategy
  fallback for stubborn Yes/No widgets that ignore `.click()`. The
  React-native-setter approach (Strategy 4 — finds the hidden
  `<input type="checkbox">`, calls the native value setter, dispatches
  `change`) is what cracks most of them.
- `--list-pending-essays` CLI mode on `ashby_apply_driver.mjs`. Outputs
  unique pending essay questions across the queue so a future
  main-Claude-in-loop session can batch-author the answers.

### Fixed
- React-select Location combobox now reliably opens via
  `MouseEvent("mousedown", {button: 0, buttons: 1, clientX, clientY})`.
  Plain `.click()` silently failed on the async Google Places picker.
  Reference impl: `reactSelect()` in `greenhouse_apply_driver.mjs`.
- UUID id selectors (e.g. `72b55bca-...`) now use the
  `[id="..."]` attribute selector instead of `#<id>`. Naked `#<id>`
  is invalid CSS when the id starts with a digit. The driver + helper
  modules both handle this — we learned the same lesson twice; do not
  un-fix it.
- File upload race: React unmounts `#resume` immediately after
  `setFileInputFiles` completes. The driver no longer tries to
  re-access the element on the verify step; it checks body text
  instead.
- Driver tabs are now closed on submit/skip. v2.0 was leaking ~18
  stale tabs per batch.
- Ashby Yes/No widget false-positive: `findEmptyRequired` no longer
  flags an `[uploaded]` resume input as required-empty. The check
  is now `el.type === 'file' ? el.files.length > 0 : !!el.value`.

### Changed
- `mrweirdo-onboard/SKILL.md`: removed the `daily_apply_cap: 50`
  blanket cap. Per-company quota (`quota_guard_enabled`) is the only
  rate limit now. Step 9 of the skill is informational rather than
  gating. Users hitting a personal pace limit can cap manually.
- Essay handling is config-driven via `shared/answer_bank.json`
  instead of hardcoded in driver source.

### Known limitations (carry-over to v2.2)
- 8 directive-company variations: the ack-widget click does not
  register despite identical DOM classes to widgets that do work.
  `Ashby.clickAckWidget` Strategy 4 is the closest thing to a fix
  shipped; a separate agent is still investigating.
- Lever forms detect CDP `setFileInputFiles` and report a bogus
  "File exceeds 100MB" error on resumes that are visibly < 200 KB.
  No workaround yet. Drag-drop upload may sidestep it.
- GH `candidate-location` Google Places autocomplete occasionally
  returns 0 options on slow connections. Mitigated by a 3.5s wait,
  not eliminated.
- Forms requiring assets the user does not currently have (GPA, SAT/ACT
  scores, 1-minute intro video, official transcript) are correctly
  skipped with an explicit `skip_reason`. Profile gap, not bug.

## [1.3.0] - 2026-05-25 — Full namespace migration off `ats`

Completes the v1.2.0 rebrand by moving the user state directory and all
env var names off `ats` entirely. No backward-compat shim — at v1.2.0 no
end-users had installed yet, so a clean break was safer than carrying
two namespaces forever.

### Renamed

- **User state dir**: `~/.ats-skills/` → `~/.mrweirdo-jobs/`
- **Env vars**:
  - `ATS_HOME` → `MRWEIRDO_HOME`
  - `ATS_REPO_ROOT` → `MRWEIRDO_REPO_ROOT`
  - `ATS_DB_PATH` → `MRWEIRDO_DB_PATH`
  - `ATS_SKILLS_REPO_URL` → `MRWEIRDO_REPO_URL`
  - `ATS_SKILLS_BRANCH` → `MRWEIRDO_BRANCH`
  - `ATS_CHROME_PROFILE` → `MRWEIRDO_CHROME_PROFILE`

### Files touched

- `setup.sh`: REPO_URL, all paths, all env refs
- `shared/paths.mjs`: home dir default + all env reads
- `shared/local_db.mjs` / `quota.mjs` / `feedback.mjs` / `computer_use_locator.mjs`
- `shared/chrome-cdp-launcher.sh`
- `shared/migrate_notion_to_local.mjs`
- `shared/onboarding/*.mjs`, `shared/sourcing/*.mjs`, `shared/matching/*.mjs`
- All 12 `.claude/skills/*/SKILL.md`
- `README.md` / `HANDOFF.md` / `DISCLAIMER.md` / `examples/*`

### Preserved (deliberately)

- `/tmp/ats-skills/` — transient scratch, not user state
- Internal function name `atsHome()` in `paths.mjs` — internal API used by
  6 other shared modules; renaming would just churn callers. The public
  surface (env vars + paths) is fully migrated; internal names left alone.
- Historical CHANGELOG entries (v0.x / v1.0 / v1.1) — keep their original
  paths and command names for accuracy.

## [1.2.0] - 2026-05-25 — Rebrand to mrweirdo-jobs

Project rebranded from `ats-skills` to `mrweirdo-jobs` under the
Mr. Weirdo Jobs brand.
Everything works the same; the changes are user-facing names only.

### Renamed

- **GitHub repo**: `glin23/ats-skills` → `glin23/mrweirdo-jobs`
  (GitHub auto-redirects old URLs, but new clones / install commands should
  use the new URL).
- **Slash commands** (all 12 skills):
  - `/ats-skills` → `/mrweirdo-jobs` (batch orchestrator — same name as repo)
  - `/ats-init` → `/mrweirdo-init`
  - `/ats-source` → `/mrweirdo-source`
  - `/ats-confirm` → `/mrweirdo-confirm`
  - `/ats-greenhouse` → `/mrweirdo-greenhouse`
  - `/ats-ashby` → `/mrweirdo-ashby`
  - `/ats-lever` → `/mrweirdo-lever`
  - `/ats-smartrecruiters` → `/mrweirdo-smartrecruiters`
  - `/ats-icims` → `/mrweirdo-icims`
  - `/ats-jobvite` → `/mrweirdo-jobvite`
  - `/ats-handshake` → `/mrweirdo-handshake`
  - `/ats-workday` → `/mrweirdo-workday`
- `.claude/skills/ats-*/` directories renamed to `mrweirdo-*/`
- README.md, setup.sh, all SKILL.md frontmatter `name:` fields updated

### Unchanged (deliberately preserved for stability)

- **User data dir**: `~/.mrweirdo-jobs/` stays. Renaming would break existing
  installs and require migration scripts. The data location is internal
  implementation detail; users rarely cd into it.
- **Env vars**: `$MRWEIRDO_HOME`, `$MRWEIRDO_REPO_ROOT`, `MRWEIRDO_DB_PATH` stay.
- **Historical CHANGELOG entries** (v0.x, v1.0, v1.1): keep their original
  `/ats-X` references for historical accuracy. Those slash commands
  worked at the time of those releases.
- **Tags**: v1.0.0 / v1.0.1 / v1.1.0 / v1.1.1 stay as-is (immutable history).

### Install command

```bash
bash <(curl -fsSL https://raw.githubusercontent.com/glin23/mrweirdo-jobs/main/setup.sh)
```

(The old `glin23/ats-skills` URL still 302-redirects to the new repo for
the next ~30 days per GitHub's policy, but new installs should use the
new URL.)

## [1.1.0] - 2026-05-24 — SQLite + Datasette, zero cloud

Replaces Notion as the job-tracking DB with local SQLite. New users no longer
need a Notion account, integration token, or any cloud setup.

### Added
- `shared/local_db.mjs` (~340 lines) — SQLite wrapper using Node 24+
  `node:sqlite`. Same API surface as `notion_sync.mjs` (upsertJob /
  batchUpsert / markApplied / markSkipped / markConfirmed /
  queryApprovedView / queryAiSourcedPending / queryRecentlyApplied) so
  swap is a one-line import change. Schema:
  - `jobs` table: 25+ columns matching v1.0 Notion schema
  - 5 SQL views: `v_ai_sourced` / `v_approved` / `v_submitted` / `v_skipped`
    / `v_large_company_pending` (auto-rendered as Datasette pages)
  - `feedback` table mirrors feedback.jsonl, queryable in Datasette
- Datasette as optional zero-config web UI (`pip install datasette &&
  datasette serve ~/.mrweirdo-jobs/jobs.db --open`).

### Changed
- `/ats-init` SKILL.md: dropped from 9 steps to 6 steps. No more Notion
  integration token, no more parent-page id, no more MCP-driven view
  creation, no more `config.json` writing. Just: API key → resume parse →
  4 questions → SQLite init.
- `/ats-source`, `/ats-skills`, `/ats-confirm` SKILL.md: switched
  `import(... /shared/notion_sync.mjs)` → `local_db.mjs` (one-line change
  per file). Pre-flight checks updated to verify `jobs.db` exists.
- `README.md`: rewritten for v1.1 — emphasizes "zero cloud", documents
  Datasette setup, drops Notion requirement from prerequisites.

### Deprecated (kept for compatibility)
- `shared/notion_sync.mjs` — retained as a Notion mirror tool for v1.0
  users with existing Notion DBs. Header notice now flags it as
  non-primary. Future migration script will let users export Notion → SQLite.
- `shared/onboarding/notion_setup.mjs` — same.

### Why this matters
v1.0 onboarding had 4 Notion-specific steps (build integration, share page,
get parent_page_id, MCP view creation). Each one was a friction point
where non-technical users could fail. v1.1 reduces install + onboarding
total time from ~15 min to ~5 min for a brand-new user, with stricter
privacy: job data never leaves the machine.

## [1.0.0] - 2026-05-24 — Open OSS, self-host

The project moves from a private daily-driver to "anyone can install + run."

### Added
- **`/ats-init`** skill — 9-step onboarding orchestrator. Collects API keys
  (writes `~/.mrweirdo-jobs/.env` chmod 600), parses resume PDF via Anthropic
  native PDF support, asks 4 questions to build target_filters, provisions a
  Notion 「📋 岗位追踪」 database with 20+ properties + 4 views, smoke-tests
  one Greenhouse fetch.
- **`/ats-confirm`** skill — Gmail confirmation loop. Reads threads labeled
  `applied-jobs` (user-built filter), Sonnet-parses each into
  {company, role, ats, is_confirmation}, matches to ✅ 已投 Notion rows,
  marks them ✅ 已确认. Uses the Anthropic-bundled
  `mcp__claude_ai_Gmail__*` MCP — never scans the full inbox.
- `shared/paths.mjs` — central path / config resolver. MRWEIRDO_HOME / MRWEIRDO_REPO_ROOT
  env, profilePath() / configPath() / loadProfile() / loadConfig() /
  loadCompanyList() / loadEnv() / notionDbId() / notionViewId(). All other
  modules + skills import from here.
- `shared/onboarding/resume_parser.mjs` — Anthropic native PDF → structured
  JSON (personal / education / work_authorization / demographics /
  experience_summary / skills / languages).
- `shared/onboarding/notion_setup.mjs` — Notion DB + full schema creator
  via REST API.
- `shared/config.template.json` — schema for `~/.mrweirdo-jobs/config.json`.
- `shared/notion_sync.mjs`: `markConfirmed(pageId, {confirmed_at, email_id})`
  + `queryRecentlyApplied(days=14)` helpers.

### Changed
- **`setup.sh`** is now a curl-pipe bootstrap:
  `bash <(curl -fsSL https://raw.githubusercontent.com/glin23/mrweirdo-jobs/main/setup.sh)`.
  Clones to `~/.mrweirdo-jobs/repo`, symlinks `.claude/skills/*` into
  `~/.claude/skills/` so Claude Code globally picks them up, creates
  `~/.mrweirdo-jobs/{log,.env}`. Idempotent + re-runnable for updates.
- All `.claude/skills/*/SKILL.md` files: removed hardcoded
  `/Users/lee/Projects/ats-skills/` paths and `/Users/lee/Desktop/用户_Lin_Resume.pdf`
  resume path. New pattern:
  ```bash
  export MRWEIRDO_HOME="${MRWEIRDO_HOME:-$HOME/.mrweirdo-jobs}"
  export MRWEIRDO_REPO_ROOT="${MRWEIRDO_REPO_ROOT:-$MRWEIRDO_HOME/repo}"
  PROFILE="$MRWEIRDO_HOME/profile.json"
  RESUME=$(jq -r .resume_path "$MRWEIRDO_HOME/config.json")
  ```
  Legacy `shared/profile.json` fallback retained so existing v0.9.1 setups keep
  working unchanged.
- `shared/notion_sync.mjs:45` — DATABASE_ID now resolves through
  `paths.mjs.notionDbId()` (env → config.json → legacy default).
- `README.md` — rewritten for v1.0 audience. One-line install command.
  Per-skill descriptions. Privacy note. Gmail filter tutorial.

### Migration for existing users
Existing `v0.9.1` setups keep working:
- If `~/.mrweirdo-jobs/profile.json` missing, code falls back to
  `<repo>/shared/profile.json`
- If `~/.mrweirdo-jobs/config.json` missing, the legacy Notion DB id is
  used as fallback.
- All view IDs default to the legacy 36a1e8ce-prefixed ids.

To migrate to the v1.0 path layout: run `/ats-init` (it preserves nothing —
generates fresh config + profile). Or copy `~/Projects/ats-skills/shared/profile.json`
to `~/.mrweirdo-jobs/profile.json` and write a minimal `~/.mrweirdo-jobs/config.json`
with `notion_db_id` + `resume_path`.

## [0.7.0] - 2026-05-23 (stretch, untested)

### Added
- Workday platform support (per-company config-driven adapter)
- `.claude/skills/ats-workday/SKILL.md`
- `shared/workday/workday_helpers.js` (generic Workday DOM operations)
- `shared/workday/_template.json` + 5 placeholder company configs
- "How to add a new company" PR guide in SKILL.md

### Known limitations
- v0.7 ships scaffolding only — no real company config verified
- Tenant variant problem solved by per-company configs, NOT generic generalization
- Multi-step wizard handling needs dogfood iteration

## [0.6.0] - 2026-05-23 (beta, untested)

### Added
- Handshake platform support (best-guess helpers based on web research)
- `.claude/skills/ats-handshake/SKILL.md`
- `shared/handshake_helpers.js`
- `shared/sourcing/handshake_search.mjs` (stub — needs implementation)
- Auto-detect redirect to external ATS (Greenhouse/Ashby/Workday)

### Known limitations
- v0.6 helpers are best-guess; field selectors will need adjustment after first real submission
- Sourcing stub not implemented

## [0.5.0] - 2026-05-23

### Added
- v0.5 batch orchestrator upgrade:
  - Queue source = Notion "✅ Approved (Ready to Apply)" view
  - URL-based ATS dispatch (regex → ats-greenhouse / ats-ashby helper)
  - feedback.jsonl write on success+fail (~/.mrweirdo-jobs/feedback.jsonl)
  - Computer Use visual fallback via computer_use_locator.mjs (vision-based element ID when CDP selector fails)
- `shared/feedback.mjs` — load/append/format ~/.mrweirdo-jobs/feedback.jsonl
- `shared/patterns.mjs` — analyze skip patterns + suggest profile updates (借鉴 Career-Ops patterns skill)
- `shared/computer_use_locator.mjs` — vision fallback coordinator + JSONL telemetry

### Changed
- Submit success now writes to feedback.jsonl in addition to Notion mark
- v0.5 dashboard shows top-3 skip patterns from feedback summary

## [0.3.0] - 2026-05-23

### Added
- AI sourcing pipeline `/ats-source` skill:
  - Greenhouse Job Board API client (`shared/sourcing/greenhouse_board_api.mjs`)
  - Ashby Job Board API client (`shared/sourcing/ashby_board_api.mjs`)
  - Seed company list with 16 entries (`shared/sourcing/company_list.json`)
- AI scoring with multi-dim output (`shared/matching/ai_scorer.mjs` + `prompt_template.md`):
  - 6 dim_scores: role_fit / skills_match / location_fit / visa_compatible / seniority_match / exclude_check
  - Anthropic SDK via Node 24 built-in fetch (no SDK dep)
  - ~$0.003/job cost
  - Concurrency worker pool with retry + cost log
- Notion HTTP API client (`shared/notion_sync.mjs`):
  - upsertJob / batchUpsert / markApplied / markSkipped
  - queryApprovedView / queryAiSourcedPending
  - 3 req/sec throttle + 429/5xx retry
- Configurable filter schema (profile.template.json `target_filters`):
  - role_types / locations / exclude_keywords / min_fit_score / visa_must_sponsor
- v0.2 bug fixes:
  - Greenhouse `candidate-location` Google Places autocomplete: `prepareLocationCombobox` + `pickLocationOption` 2-step solution
  - Ashby `clickYesNo` verification false negative: wait+retry on _active_ class
  - Ashby `findEmptyRequired` missing Current Location combobox: detect by placeholder + walker pattern

### Notes
- First v0.3 dogfood pending — verify AI sourcing top-10 with manual picks.
- Cost: $0.15/week at 50 sourced jobs/week

## [0.2.0] - 2026-05-23

### Added
- Batch orchestrator skill `/ats-skills` (.claude/skills/ats-skills/SKILL.md)
  - Auto-loads queue from user's Notion 「🔵 未投」 view
  - Filters to alive Greenhouse + Ashby URLs
  - Single upfront authorization ("go") for the whole batch
  - Claude-driven field fallback for unrecognized required fields
  - Auto-marks Notion 「✅ 已投」 on success
  - Dashboard report with per-application status
- `GH.normalizeProfile()` / `Ashby.normalizeProfile()` — transforms nested profile.json to flat fillForm shape
- `GH.findEmptyRequired()` / `Ashby.findEmptyRequired()` — returns required-but-empty fields with labels for Claude reasoning
- `/tmp/ats-skills/log/<date>.jsonl` per-attempt log

### Fixed
- **pickOption 1.5s poll too short** — NiCE picker takes >600ms to render options after openPicker. Bumped to 3s + initial 200ms render wait.
- **Picker out-of-viewport** — React lazy-renders .select__option only when picker is visible. openPicker now scrollIntoView({block: 'center'}) first.
- **Schema mismatch** — profile.template.json was nested but fillForm expected flat. v0.2 normalizers bridge both.

### Notes
- First real dogfood: NiCE SDR Intern Sandy UT (Greenhouse), 2026-05-23. Submitted successfully; confirmation URL /nice/jobs/4754106101/confirmation; "Woohoo! We received your application!"

## [0.1.0] - 2026-05-23

### Added
- Initial release
- shared/cdp.mjs — Node 24 WebSocket CDP driver (zero-dep). Commands: tabs, goto, eval, upload, screenshot, typetext, cdp (raw).
- shared/chrome-cdp-launcher.sh — Dedicated Chrome instance via `open -na` with isolated ~/.mrweirdo-jobs/chrome-profile.
- shared/greenhouse_helpers.js — react-select v5 mousedown picker, iti country, custom_answers/picker_answers by label.
- shared/ashby_helpers.js — react-hook-form text via CDP typetext, Yes/No buttons, _systemfield combined name, date picker.
- .claude/skills/ats-greenhouse/SKILL.md + .claude/skills/ats-ashby/SKILL.md — per-ATS single-URL flows (kept in v0.2 as power-user shortcuts).
- README.md, LICENSE (MIT), DISCLAIMER.md, setup.sh, shared/profile.template.json.

### Not supported
- Workday (form variants too high; per-company breakage)
- Lever (no working code yet)
- Handshake (no working code yet)
- LinkedIn Easy Apply (TOS red line)

[0.7.0]: https://github.com/glin23/mrweirdo-jobs/releases/tag/v0.7.0
[0.6.0]: https://github.com/glin23/mrweirdo-jobs/releases/tag/v0.6.0
[0.5.0]: https://github.com/glin23/mrweirdo-jobs/releases/tag/v0.5.0
[0.3.0]: https://github.com/glin23/mrweirdo-jobs/releases/tag/v0.3.0
[0.2.0]: https://github.com/glin23/mrweirdo-jobs/releases/tag/v0.2.0
[0.1.0]: https://github.com/glin23/mrweirdo-jobs/releases/tag/v0.1.0
