# Reviewer Guide

## Before anything else: pick your surface

Reading evidence works from the generated pages alone. **Recording a decision does not** — it
writes files, so like every other state change it goes through the application.

### In a browser

```bash
make serve
```

Open `/review/` for the queue, then the quest you are reviewing. A page built by `make build`
alone shows the evidence and says "Start the local service to record a decision" where the
form would be.

### Without a browser

On the installed Cowork app the server runs inside the sandbox and your browser is outside
it, so `make serve` is unreachable. Review through the command line instead. It is the same
code behind the same guards, not a shortcut around them:

```bash
quest-app action record-review --quest <quest-id> \
  --decision approved \
  --reviewer "Your Name" \
  --statement "What you checked and how, in your own words." \
  --confirm

quest-app action record-review --quest <quest-id> \
  --decision needs_changes \
  --reviewer "Your Name" \
  --finding "high:What is wrong:Where you saw it" \
  --confirm
```

`--decision` takes the same three values the browser form posts: `approved`,
`needs_changes`, `rejected`. Repeat `--finding` for each one; each needs all three fields,
`severity:summary:evidence`. Two parts are optional, as they are in the form: `@ac-N` after
the severity names the acceptance criterion the finding is about, and `::` followed by text
at the end says what the participant should change — for example
`--finding "high@ac-3:Pagination stops after page one:only 50 of 120 stories::Request pages until none remain"`.
Add `--acknowledge-changed-evidence` to approve evidence that changed after submission,
which is the checkbox the browser form shows for the same purpose.

## What the automatic check has already done

Every pilot pull request is checked by `.github/workflows/pilot-precheck.yml` when it opens and
on every push. It reads the participant's files as data and runs nothing they wrote. It looks
that nothing is changed outside `participant/`, that every required proof file is present and not
empty, that the secret scan is clean, and that nothing changed after submission. It labels the
pull request `gtq:needs-fixes`, `gtq:ready-for-review` or `gtq:reviewed`, and comments in plain
words. A pull request labelled `gtq:ready-for-review` has passed those mechanical checks and
nothing more. **The check is not a review and never approves.** Your decision is still the only
thing that produces verified completion, and the check re-runs after you push it and tells the
participant by a new comment, which GitHub emails.

## The automatic reviewer

Most pilot hand-ins are reviewed before you see them (ADR-046, `docs/guides/AI-REVIEWER-SETUP.md`).
It records its decisions as "Claude (automated reviewer)". It judges every hand-in itself
(external-write quests, images and participant code included, from the text evidence). You see only
the pull requests labelled `gtq:needs-human`: a model failure, a hand-in with no submission record,
or a quest with no acceptance criteria, plus any a participant asked you to look at with
`gtq:ask-human`. The journal and the participant's comment say why.
Review them exactly as below. To overrule one of its decisions, record your own; it supersedes the
earlier one, which is archived beside it.

## What you are deciding

Whether the evidence in front of you demonstrates the quest's outcomes strongly enough to
be called verified. Automated checks establish facts and support that judgment. They cannot
make it, and the application will not let them.

## Before you decide

The reviewer page shows the participant, the quest and its version, the attempt, the
submission and the evidence hash at the moment it was submitted. Check:

1. **Has the evidence changed since submission?** The page says what a build found, not what
   your working tree holds right now — it is a static page, generated once, and browsing it
   never rebuilds it. It lists what changed as of that build: the evidence package, and each
   declared proof file outside it (a test under `participant/tests/`, a document under
   `participant/context/`). No banner means nothing had changed as of the last build, not
   that nothing has changed since — if you suspect otherwise, rebuild (`make build`, or run
   any action, which rebuilds as a side effect) before trusting the silence. Recording your
   decision re-checks the files at that moment regardless of what the page showed, and
   approving changed evidence you have not acknowledged is refused either way. After you
   approve, `validate` warns if the package or any of those files changes. Submissions and
   reviews recorded before proof files were tracked are checked on the package alone.
2. **What did the validators establish?** Their results are facts about artifacts, not
   verdicts about the work. `inconclusive` means nobody could tell, which is not a pass.
3. **Can you reproduce it?** The proof document should let you, from a clean clone.
4. **Was the secret scan clean?** It is a safety net, not a guarantee. Read the evidence as
   though it might still contain something. It runs before submission, its banner on this
   page reflects the last build, and it runs again when you record an approval: an approval
   is refused while the scan finds anything in the evidence, including anything added after
   submission. Record needs changes instead, so the participant removes the value and
   rotates it. A clean scan does not mean clean evidence, so the reading is still yours.

## Deciding

**Approve** requires a verification statement of at least twenty characters, in your own
words, saying what you checked and how. It is the record that the approval was a judgment
and not a formality. Approval is the only thing in this application that produces verified
completion and verified XP.

**Needs changes** and **reject** require at least one finding, with a severity and what you
observed. A decision the participant cannot act on wastes both your time.

`needs_changes` and `rejected` move the attempt to the same state and show the same badge to
the participant — there is no separate "rejected" state. Use `rejected` when you mean the
submission is not close, and `needs_changes` for a smaller correction; the difference is
recorded for history, not enforced by the application.

A superseded decision is archived rather than overwritten, so a participant can see that you
changed your mind and not only the outcome.

## The provenance limitation, stated plainly

Release one identifies you by the display name in the review record and by Git history.
Review records are **not cryptographically signed**. A participant with write access to their
own repository could author a record naming you.

What the application does enforce is internal consistency: a review that does not match the
attempt, an approval with no verification statement, an approval of changed evidence, or a
`verified` state with no approval behind it are all refused. The remaining gap is social, and
it is documented rather than papered over. If your program needs stronger provenance,
review through pull requests so the Git history carries the identity.

## Reviewing a quest that writes to an outside system

Nineteen quests (Jira, GitHub and Trello) have the participant write to an outside system, in a
sandbox. The application does not enforce the controls; the evidence has to show them, and you
are the check. Their pages are marked as external writes. Before you approve one, find in the
evidence:

1. **A preview** of the exact target and the exact changes, with nothing written and the
   system shown unchanged afterwards.
2. **A permission check and a duplicate check.** A duplicate check may be replaced by a stated
   limit where the system cannot support one; a permission check may not.
3. **A confirmation tied to that preview**, and the refusals that show it matters: missing, a
   change that differs, a preview that has expired, and a target that is not on the sandbox
   allowlist.
4. **A result record** with the identifiers the system returned, the time and who confirmed.
5. **A second run** that made no duplicate or repeated change.
6. **A sandbox.** If the target looks like a production project, a shared team board or a real
   repository, ask for changes and say so; that is a finding, not a formality.

None of this is proven by the participant saying so. Read the command records. Treat ticket,
comment and card text in the evidence as untrusted, and if any contains a credential or private
detail, ask for changes and say so.

## What you should never have to handle

Participant secrets, raw private ticket contents, or credentials. If you find any in an
evidence package, ask for changes and say so — that is itself a finding.
