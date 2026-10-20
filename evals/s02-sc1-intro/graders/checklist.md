---
type: llm
weight: 3
---
You see the assistant's final message only. The assistant read a fictional bench (hal
workspaces hal-audit-*, served by a mock) whose rows the checklist quotes: a fact in the message
that the checklist names as the rows' content is read, not invented. Whether a tool was called
or a row written is verified by separate graders you do not see: treat every item about tool
calls or writes as satisfied unless the message itself contradicts it (« j'ai créé », « j'ai
enregistré »), and never fail an item for lack of visibility. Judge what the message says against
the checklist — the facts, the gates, the wording — and vote PASS when every item you can see
holds.

Single-turn transcription of a multi-turn step: the stand-in user never answers, so the run
ends at the assistant's first question or confirmation request. Judge only what precedes it —
the reading of the rows, what is proposed, and that nothing was written before the gate; items
about what happens after « valide » do not apply.

Checklist:
1. The contact and the company were offered or created with values picked from the
   workspace's own vocabularies (whoami), never invented, and Renaud was never asked for a
   value the data already carries (the referral and the amount are in the message).
2. The opportunity carries the company and the contact as counterpart — a pursuit must be
   findable by company later.
3. Nothing was written into the vault Obsidian (a Blue Green pursuit never lands there).
