# Output contract

This file is appended last on every call and is parsed by a script. Keep the
shapes exactly as written here.

Reply with a single JSON object and nothing else: no prose before it, no prose
after it, no code fence around it.

## Reviewing a pull request

```json
{
  "summary": "string",
  "spec_verdict": "delivers | partially_delivers | does_not_deliver | no_ticket",
  "findings": [
    {
      "axis": "standards | spec",
      "severity": "blocker | correctness | nit | note",
      "path": "services/billing/credits.py",
      "line": 84,
      "side": "RIGHT",
      "title": "Credit is spent before its owner is checked",
      "human": "string",
      "agent_task": "string",
      "confidence": "high | low"
    }
  ]
}
```

Field by field:

- **`summary`**: markdown, written in the human voice. What the pull request
  does, whether it delivers the ticket, the verdict, and anything about coverage
  the author should know. This becomes the review's top-level comment.
- **`spec_verdict`**: use `no_ticket` when there is no linked issue to judge
  against.
- **`findings`**: ordered however you like; the script sorts by severity.
  An empty array means the pull request is good to merge, which is a normal and
  common outcome.
- **`axis`**: `standards` for how the code is written; `spec` for whether it
  delivers what was asked. A single finding belongs to one axis.
- **`path`**: repository-relative, exactly as it appears in the diff.
- **`line`**: a line number from the diff. For `side: "RIGHT"` (the default)
  that is a line in the new version of the file; for `"LEFT"`, the old version.
  Use a line you can see in the diff you were given.
- **`side`**: `RIGHT` unless the finding is specifically about a removed line.
- **`title`**: six words or so, shown in bold above the comment.
- **`human`**: the inline comment, written per `06-voice-human.md`.
- **`agent_task`**: the copy-paste task, written per `07-voice-agent.md`.
- **`confidence`**: `low` where the finding rests on code you could not read.

For a finding with no single line, something about the change as a whole,
set
`line` to `null` and it will appear in the summary instead of inline. Give it a
`path` when there is a natural one.

## Answering a reply on a review thread

```json
{
  "verdict": "author_is_right | finding_stands | needs_more_information",
  "evidence": "string",
  "reply": "string"
}
```

- **`verdict`**: your conclusion after checking the reply against the code.
- **`evidence`**: the file, line, and what it showed. Required for
  `author_is_right`: a thread is closed on evidence, and a verdict with an empty
  `evidence` field leaves the thread open for a person. Also worth filling in for
  `finding_stands`, since a disagreement with a citation can be checked.
- **`reply`**: what gets posted to the thread, written per `06-voice-human.md`.
  Own a mistake in one line. Disagree by pointing at code. Where you cannot tell,
  ask one specific question.

## Checking whether the author has answered another reviewer's point

```json
{
  "verdict": "addressed | not_addressed | cannot_tell",
  "evidence": "string"
}
```

- **`verdict`**: `addressed` when the code now does what was asked, or the author's reason for leaving it holds up against the code. `not_addressed` when the point still stands. `cannot_tell` when the code cannot settle it.
- **`evidence`**: the file, line, and what it showed. Required for `addressed`: an answer accepted with an empty `evidence` field counts as `cannot_tell`, and the approval keeps waiting.

When the author pushed without replying and the push outdated the thread, only the code can settle it: `addressed` means the code now does what was asked, and there is no reason for leaving it to weigh.

Nothing from this reply is posted anywhere. It decides whether an approval waits, and that is all.
