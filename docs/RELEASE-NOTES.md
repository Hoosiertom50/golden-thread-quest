# Release Notes: Pilot Release

**Version:** 0.3.1
**Date:** 2026-10-22
**Status:** released to a small invited pilot, not for general use. The release checklist
passed (`docs/audits/phase-01-verify.md`), and the program owner released it at Gate 1
(`docs/audits/final-audit.md`). Pilot participants start with `docs/guides/PILOT.md`.

## What changed in 0.3.1

- **The Quest Map is a drawn map.** An atlas-style picture: a continent with a rough coast and
  shaded relief, rivers, lakes, mountains and forests, a dark sea, and a dotted trail through the
  regions in curriculum order. Each region is land sized by its quest count, with a picture
  chosen by a new optional `terrain` field on the region (Base Camp at the foot of a mountain,
  GitHub Caverns at a cave mouth, Trello Islands out at sea as its own island) and a label
  reading, for example, "0 of 18 verified". A region's marker glows brighter as more of its
  quests are verified.
  Selecting a region opens its card in a dialog; without scripting the label goes to the region page.
  The card list stays below the map for anyone who prefers text. The layout is computed from
  quest counts alone, in `quest_app/map_layout.py`, and is the same on every build. This is
  content-visible but changes the page. The user guide shows it.
- **CI runs the tests in shards**, because one job outgrew GitHub's six-hour limit.

## What changed in 0.3.0

- **The whole curriculum.** 128 quests across nine regions, up from eight quests, one per
  region: Base Camp 9, BA Ruins 13, Scrum Village 9, Context Library 12, Playwright Labyrinth
  20, Jira Jungle 23, GitHub Caverns 18, Trello Islands 17, and a new region, Trap Cards, with
  7 adversarial challenges. Every row of `docs/CURRICULUM-BACKLOG.md` now has a quest. The
  quests are content only: no application code, schema, template or validator changed.
- **Nineteen quests write to an outside system, to a sandbox.** They are the first that
  declare `risk.external_write: true` (Jira 7, GitHub 6, Trello 6). Each requires a preview of
  the target and exact changes, permission and duplicate checks, a confirmation tied to the
  preview, a result record with identifiers and a time, rerun safety and a sandbox allowlist.
  The application still performs no write; these are controls the participant builds and the
  reviewer reads. `tests/test_release_facts.py` now holds them in the content: it names the
  nineteen quests and fails if any control is missing from a quest's required proof, if a
  write quest is untagged, or if one is added without being named. The old test, which said no
  quest writes, is replaced by this stricter one. `docs/SECURITY-AND-PRIVACY.md` says what is
  and is not enforced.
- **A test helper handles shared prerequisites.** `unlock` in the integration tests skips a
  prerequisite already verified, so a quest reachable by two paths can be tested.
- **The pilot quest is unchanged.** `ba-ingest-transcript` keeps its version, and so do the
  seven other original quests. A participant's existing progress is unaffected.

What this release does not do: nobody outside the project has reviewed the content of the new
quests, only independent audit passes (`docs/audits/curriculum-final-audit.md`). Participants
who want to do a write quest need a sandbox Jira project, GitHub repository or Trello board;
who provides them is not yet decided.

## What changed in 0.2.4

- **No "Request timed out" lines after a normal page load.** A browser keeps spare
  connections open; the application closes them after 30 seconds, and used to report each
  one in the terminal, which read as a failure. Other errors are still reported. Found by
  the Phase 2A.2 demo.

## What changed in 0.2.3

- **Setup finds the participant's copy on GitHub.** 0.2.1 and 0.2.2 made the fork, then
  checked it through a field the GitHub tool does not provide, so setup stopped at step 5
  with "Could not make your copy on GitHub" for every participant. Found by the Phase 2A.2
  demo, the first run against real GitHub. The check now uses GitHub's documented answer,
  and a test runs setup's GitHub step against recorded GitHub responses.
- **Setup on the account that owns the quest says so,** instead of suggesting a repository
  be renamed. An account cannot fork its own repository; sign in with your own.

## What changed in 0.2.2

First-day fixes for business analysts and manual testers (Phase 2A.2).

- **The transcript quest comes first.** *Ingest a Meeting Transcript Without Losing Its
  Source* (BA Ruins) no longer needs Base Camp verified first; it is now quest version 4.
  New participants start on the *Pilot for Analysts and Testers* track, which lists it
  before Base Camp, and the home page follows the track's order. An attempt started on
  version 3 is reported as on an older version; none exists, since the invitation was not
  yet sent.
- **Hand-in names what it left out.** A file under `participant/` that matches
  `.gitignore` (a `*.token` file, anything in a `secrets/` folder, and the rest) is still
  never handed in, but `gtq hand-in` now lists each one and says what to do if it is proof
  the quest asks for. The application's own lock file and what an operating system drops
  into a folder (`.DS_Store`) are not listed.
- **Ignored files are not part of the evidence fingerprint** (ADR-031, amended), since the
  reviewer's copy never has them. A `.DS_Store` no longer makes an approved quest read as
  changed.
- **The home page's "Start at" box names the recommended quest's region**, not always the
  first region on the map.
- **Setup makes no unsigned GitHub API call.** It reads the GitHub tool's latest version
  from the release page instead of the API, which allows 60 unsigned requests an hour per
  address and could stop a room of participants behind one office address.

## What changed in 0.2.1

Pilot participants are business analysts and manual testers, not developers (Phase 2A.1).

- **Setup is one pasted line on a Mac, Linux or Windows WSL: `install.sh`.** It installs
  what is missing, asking before each install: Apple's command line tools or Git, uv (which
  brings its own Python) and the GitHub command line tool. Then it signs the participant in
  to GitHub in the browser, forks and clones the repository, creates their `pilot/<name>`
  branch at `v0.2.1`, installs the application and starts it. Running it again is safe.
- **`gtq start`, `gtq hand-in` and `gtq get-review`,** from any folder. Hand-in commits
  `participant/`, pushes it and opens or updates the participant's pull request. Get-review
  brings in the reviewer's decision, names it, and rebuilds the site so a reload shows it.
  Both explain every refusal in plain words (ADR-044).
- `quest serve --open` opens the home page in a browser.
- `docs/guides/PILOT.md` is rewritten for someone who has not used Git.
- **Not yet:** native Windows. The setup runs in WSL, but installing WSL is not automated.

## What changed in 0.2.0

- **A submission is refused while required proof is missing.** Any required file, folder or
  command record that the evidence page shows as *Not detected* or *Needs attention* blocks
  it, and the refusal names each one. Before this, a package with three of four required
  files missing could be submitted, and only the reviewer caught it.
- **The Base Camp check fails on an untouched `PROOF.md`.** It used to report "passed with
  advisories" on an empty package.
- **Review from a clone works.** The evidence fingerprint no longer counts empty folders,
  which Git does not carry, so a reviewer's clone of a participant's branch no longer reads
  every hand-in as "changed since submitted" (ADR-031, amended). A submission or approval
  recorded under 0.1.x reads as changed once.
- A refusal names every problem. It used to be cut at 300 characters, which dropped a
  missing file from a long list.
- The service removes its port record even if it is stopped during start-up.
- New guides: `docs/guides/PILOT.md` for participants, `docs/guides/PILOT-LEAD.md` for the
  pilot lead, and `docs/guides/DEMO.md` for a fifteen-minute tour.

## What this is

A local-first training application for The Golden Thread Quest. A participant works through
curriculum held as Markdown and YAML, assembles evidence as ordinary files in their own
repository, runs registered checks against it, and submits it to a reviewer who decides
whether it is verified.

Everything it knows lives in files. It reads them and writes a narrow, documented set of
them. It does not own them.

## What works

- **Curriculum as content.** Adding a quest is one Markdown file. It appears in its region,
  the catalog, the filters, its tag page, the search index, the relationship graph and the
  prerequisite calculation with no change to Python, Jinja2, JavaScript or CSS. A test
  asserts those three directories are byte-identical after a quest is added.
- **Content that does not validate is never published.** Schema and cross-document
  validation reports the file, the field, the rule in words, a redacted value and — for a
  mistyped stable ID — a suggestion. A failed build leaves the last good site standing and
  writes the errors as their own page.
- **Eleven screens**, specified in `docs/ui/SCREEN-SPECS.md` as U01 to U11 and rendered by
  thirteen page templates — the two extra templates are the tag page and the evidence index,
  which are generated per tag and per quest rather than being screens of their own. They are
  generated deterministically: two builds of the same inputs differ only in the build
  timestamp each page carries, and setting `SOURCE_DATE_EPOCH` to a fixed value makes them
  byte-identical. The site works served and opened from disk.
- **Every state change without a browser.** The CLI action layer performs the same actions
  through the same allowlist and the same guards, which is the only path on a Cowork sandbox
  with no terminal and no reachable loopback port. A rule the quest page enforces is enforced
  here too (ADR-033), and two processes cannot interleave one participant's progress
  (ADR-034).
- **A loopback-only service** for the things a static page cannot safely do, with a per-run
  token, origin checks, a body-size cap, and an action allowlist that no path or command
  crosses.
- **A validator framework** where a quest names a check by ID and can never supply a
  command, an argument or a path. Registered validators run in their own process group with
  a constructed environment, a timeout that kills the group, capped and redacted output.
- **Claimed and verified progress kept apart.** Nothing a participant does and nothing a
  validator returns can produce verified completion or verified XP.
- **Submissions and reviews** with the guards that make a decision mean something: a
  verification statement to approve, a finding to ask for changes, and a refusal to approve
  evidence that changed since it was submitted.
- **Updates that keep your work.** The update helper reports and stops; it runs no merge.
  In-progress attempts stay on the quest version they started.
- **Accessibility as checks, not intentions.** WCAG contrast computed from the tokens, axe
  over eleven pages with serious and critical impacts failing the build, four viewports,
  200% zoom, keyboard flows, and core content present with every script stripped.

## Numbers

| | |
|---|---|
| Tests | 1702 under `make check`, plus 65 browser-driven under `make test-ui`. Both are collected counts; a run also reports whatever it skipped. |
| Screens | 11, plus tag pages |
| Schemas | 10 |
| Sample validators | 3 quest-facing, plus 2 registered environment probes and one unregistered slow probe used only to prove the timeout |
| Build budget, the shipped curriculum plus 200 synthetic quests | asserted under 60s; observed under 1s |

## Known limitations

These are real and deliberate. Each one is written down where it matters rather than only
here.

1. **Recording a decision writes files, so it needs a writer.** A reviewer reads everything
   from generated pages. The decision itself is recorded either through the browser form,
   which needs the running local service, or with `quest-app action record-review`, which
   needs neither a browser nor the service (round 17 D1 corrected this item, which said only
   the service could).

2. **Reviewer provenance is conventional, not cryptographic** (ADR-030). A reviewer is
   identified by the display name in the record and by Git history. A participant with write
   access to their own repository could author a record naming someone else. Every
   *internally inconsistent* claim is refused; the remaining gap is social. If your program
   needs more, review through pull requests so the Git history carries the identity.
3. **Environment Health reports build-time facts, not live ones.** A generated page cannot
   inspect the machine at the moment it is read. It reports the application and content
   version, Python, Git branch and upstream, the output directories and — on a page the
   running service built — the service itself, each as of the build (round 17 L6). A write
   test and which external CLIs are installed need a live read and remain deferred (D7).
4. **Reviewer-awarded badges cannot yet be awarded.** There is no badge-award record type, so
   meeting the criteria shows as "pending". Granting one by arithmetic would be exactly the
   blurring of authority the product exists to prevent.
5. **Validator isolation is policy plus process boundaries**, not a container or seccomp. The
   architecture permits adding one without changing quest content.
6. **Catalog filtering needs JavaScript.** A static page cannot filter itself. The routes
   that work without it are real pages: regions and tags, linked from every card and quest.
7. **No coverage reporting** and **no glossary content type** (deferred items D2 and D1 in
   `docs/IMPLEMENTATION-PLAN.md`).
8. **The secret scanner cannot usefully read a binary or compressed file** (round 15
   corrected this from naming a screenshot as the one exception). Every image format
   (`.png`, `.jpg`, `.jpeg`, `.gif`, `.webp`), plus `.pdf` and `.zip`, is skipped outright —
   round 16 changed this from an extension check to a check of the file's own magic bytes,
   since a plain-text secret saved under one of these names used to pass on the filename's
   say-so alone. `.docx`/`.xlsx`/`.pptx` share the plain zip signature and are skipped the
   same way, for the same reason neither is read as text either way. A compressed or
   container format that carries none of these signatures — `.gz`, `.7z`, `.tar` and
   similar — is not skipped, but is read as opaque compressed bytes that decompress into
   nothing any pattern recognizes, so it passes with the same silence a skipped file would.
   The `PROOF.md` template asks the participant to confirm the package carries nothing
   sensitive, and that confirmation is a person's judgment for any of these formats, not a
   gate. Separately, a token glued directly onto a following `_` or letter
   (`x_ghp_<36 chars>_y`) is still missed; loosening the trailing boundary that misses it
   risks reopening the same false-positive class a leading boundary once caused (round 13
   E11 / round 14 E1), and it is left as a known gap rather than fixed without a corpus
   proving that trade safe.
9. **Clean-clone installation is tested one step short of a real clone.** The `clean-export`
   CI job runs `make verify-package`, which exports tracked files with `git archive`, then
   installs, validates and builds in a fresh virtual environment on every change. A true
   `git clone` from the remote followed by `make setup` was run by hand in round 4 and
   recorded in `docs/audits/round-04-independent-audit.md`; nothing runs it on a schedule.
10. **Earlier quest versions are not kept.** An attempt records the quest version it was
    started on, and the review page says when a newer one is published, but the quest page and
    the review page show the current version's criteria. Git history holds the earlier text.
11. **A validator's grandchild that starts a session of its own outlives the timeout.**
    `docs/VALIDATOR-CONTRACT.md` covers the ordinary case: the run's process group is
    killed on exit and on timeout, which reaches anything a validator spawns normally.
    A descendant that calls `setsid()` (Python's `start_new_session`) leaves that group
    and is not reached by the same `killpg`. Making the whole service process a Linux
    `PR_SET_CHILD_SUBREAPER` would catch a reparented orphan like that one, but only by
    landing it on the service process itself, mixed in with every other run's — with no
    cheap way to tell which run a given reparented PID came from, and nothing that ever
    kills the service process the way the per-run child is killed to clean its own up.
    That trade swaps one unbounded-survivor case for another, so this is recorded here
    rather than "fixed": every shipped validator is reviewed code that does not do this,
    and the gap only matters against one that is not.

12. **The 120 quests added in 0.3.0 have been audited, not read by their audience.** Independent
    review passes checked structure, proof coverage and safety. Nobody the quests are written
    for has worked through one yet, so expect unclear wording and wrong time estimates.
13. **The 19 quests that write to an outside system need a sandbox that nobody provides yet.**
    The application performs no external write; the controls (preview, confirmation, result
    record, rerun safety, sandbox allowlist) are in the quest content and are read by a
    reviewer. `tests/test_release_facts.py` holds them in the content, not at run time.
14. **The full test suite takes about 90 minutes in one process.** CI splits it into eight
    shards per Python version. One test, `TestThePortFileLifecycle`, fails if shards share a
    machine, because they share the service's port file.

## For the pilot cohort

Start with `docs/guides/PILOT.md`: what to install, which quests, how to hand in evidence
and how to send feedback. The pilot is still two quests, although the catalog now lists 128. For depth, read `docs/USER-GUIDE.md`, the whole-journey guide, and keep
`docs/guides/PARTICIPANT.md` beside it as the short reference. Reviewers should read
`docs/guides/REVIEWER.md`, particularly the provenance section — it says plainly what the
application does and does not guarantee about who approved what.

## Upgrading

**From 0.2.x to 0.3.0:** 0.3.0 is content only. It adds 120 quests and changes none of the
original eight, and no schema or progress-file shape changed, so `make update-check` should report
it safe, `make migrate` should have nothing to do and an existing attempt, verified or not, is
untouched. The new quests appear in your catalog after you take the update.

Otherwise there is nothing to upgrade from. Schema version 1 is the first. The migration machinery
exists already because the first real migration is the wrong moment to be designing the
safety around it.

The evidence hash rule changed in round 17 (ADR-031, amendments A-E14 and A-E15). A package that
holds a non-UTF-8 text file with Windows line endings (cp1252, Latin-1), or a directory
symbolic link inside it, hashes differently from before, so a submission or approval recorded
over such a package reads as "changed since submitted" or "changed since approval" once,
though no byte of the work moved. The reviewer re-reads the evidence and approves with the
acknowledgement ADR-030 already asks for. Packages without either hash exactly as before.

Round 17 also changed three behaviours an existing participant or reviewer can notice:

- **Approving evidence that holds a secret is refused.** The secret scan runs again when an
  approval is recorded (round 17 E5). Record needs changes instead.
- **Proof paths are shown inside your real attempt folder.** A quest names
  `…/attempt-001/logs/x.txt`; pages now show `…/<prefix>-attempt-001/logs/x.txt`, and only a
  file there counts as detected (round 17 L1, L2). A file left at the literal `attempt-001/`
  path is no longer detected, because nothing scans or fingerprints it there. Move it into
  the attempt folder the evidence page names.
- **The secret scan reports more shapes** (round 17 E1–E4, L10 and the A-series): a file
  that scanned clean before may now report a finding. The finding names the file and line.

