# GrantProof: three-minute judging demo

Working format, not a claim about the event's required video length. Use fictional records only. The app's guided entry is **Dashboard → Try the demo**. Choose **South Beach** for a light presentation, **Wynwood** for the neon/mural treatment, or **Little Havana** for warm Calle Ocho-inspired storefronts.

## Record the browser walkthrough

From the repository root, run `npm ci` and `npx playwright install ffmpeg` once, then `npm run demo:record`. The command builds the current app, starts it on an isolated loopback port with a fresh temporary fictional database, and saves a WebM video plus the downloaded HTML report and JSON audit package in ignored `demo-output/`. It shows the portfolio, prepares the Family Futures grant for staff review, and uses the South Beach theme and deterministic fixture generation, which the video labels explicitly. The script never resets the normal workspace database.

For a specifically authorized paid live SDK recording, run `npm run demo:record -- --live` with an available `OPENAI_API_KEY`. Use `--headed` to watch the browser, or `--output path.webm` to choose the video path. The script opens the saved generation activity receipt and its linked evidence; live mode also reveals a tool name, while fixture mode states that no AI was called. It verifies the visible evidence gap, the $50,000 / $16,200 / $33,800 totals, duplicate CSV handling, approval hash, actual downloads, and the export lock after an unsupported edit. Review the video and add narration before submission.

The ready-to-read [voiceover script](VOICEOVER.md) follows the recorded scenes. Record it separately, then use `npm run demo:voiceover` to combine the audio and video into an MP4.

## The opening, in plain language

“We built GrantProof to turn a nonprofit's own records into a grant report. Every claim points to approved evidence. Every dollar reconciles against the funder's categories and dates. Staff approve the exact package before it leaves. Change a claim afterward and export locks. Let me show you.”

## Show the product

**0:00–0:20 — The problem.** The supplied Tidepath challenge describes a director and bookkeeper losing days to questions, word limits, spending rules, and different funder years. Say who has the problem and show the workspace immediately. Do not claim measured customer adoption or time savings.

**0:20–0:50 — Evidence.** Open Evidence library. Show an approved 120-family record and the pending 92% estimate. The estimate cannot enter a supported draft. Imported lines are candidates that need staff review.

**0:50–1:25 — Let the agent prepare the grant.** On Dashboard, enable **Use live workflow agent**, then click **Prepare grant for review**. Show the coordinator's evidence audit, spending audit, missing-answer preparation, and readiness check. Existing answers and staff edits are preserved. Open Application to inspect a draft's own receipt and its original evidence. The pending message waits for the server rather than simulating completed actions. Fixture mode is a labeled, free walkthrough with no AI calls. Live preparation uses a coordinator run plus one drafting run per missing answer; rehearse its duration rather than promising a fixed time.

**The portfolio stretch.** Show every grant's own period, category warnings, and blockers. Staff set real report due dates; blank dates are not inferred. Use **Prepare due reports** for deadlines up to the planning date, or **Prepare all grants** for a portfolio handoff. These are user-triggered queues, not background scheduling. Near limit means 80% or more of a category is already allocated, not a predictive forecast. Bridge Fund exposes missing approved goal evidence and an unallocated transaction. The agent hands those tasks to staff through evidence/spending links. Preparation does not approve facts, allocate expenses, approve the package, export, submit, or send. Failed or conflicting preparations save no partial drafts.

Say: “This is the recorded work for this draft, not the model's private reasoning. The agent retrieves and drafts; code checks; staff approve.” Receipts persist on reload and remain labeled as historical after edits. Older drafts have no backfilled activity; regenerate to record it. Failed generations preserve the previous draft and receipt. A receipt is not an approval or proof that evidence is still current.

**1:25–2:00 — Exact money and funder rules.** Show $50,000 budget, $16,200 spent, and $33,800 remaining. Re-import `fixtures/quickbooks-sample.csv`: four duplicates are skipped and the balance stays unchanged. Briefly select Bridge Fund to show its July–June period; return to Family Futures. Explain the CSV workflow accurately: there is no direct QuickBooks connection.

**2:00–2:45 — The memorable proof.** Approve the application/report together. Download the actual readable HTML report and JSON audit package. Edit a claim to an unsupported 99% result, then return to review: approval is invalidated and export returns 409. The stored approved snapshot remains unchanged. This is the strongest finish because the audience sees a safeguard work.

**2:45–3:00 — Close.** “The model drafts. Code reconciles. Staff approve. The result is one reviewable package, with the records behind it. Next we would pilot the workflow with staff and measure preparation time, correction rate, and report completeness.” These are proposed pilot measures, not results already achieved.

## What prior winners suggest

This is our interpretation of public winner reports, not evidence of a guaranteed winning formula:

- OpenAI's winners include Second Voice, which retains user choice; veTriage, which supports an existing staff workflow; and Echo Canvas, which keeps deterministic calculations outside the model. The common lesson for GrantProof is to make the user benefit and the human/AI boundary visible. [OpenAI winner report](https://developers.openai.com/blog/build-week-winners).
- The University of Utah says its first-place project, Pieces of Them, was recognized for impact, commercial viability, and timely AI use. Our pitch should explain whose grant work improves and what a feasible staff pilot would measure. [Organizer's winner announcement](https://ai.utah.edu/blog/posts/2026/build_with_ai_hackathon-1.php).
- Devpost's guidance stresses a clear problem, usable product, concise working demonstration, and accessible submission links. Its advice from previous winners recommends planning the script and showing actual interaction. The implication here is to demonstrate the source → spending → approval lock sequence and rehearse it. [Judging guidance](https://info.devpost.com/blog/understanding-hackathon-submission-and-judging-criteria), [demo advice from previous winners](https://info.devpost.com/blog/6-tips-for-making-a-hackathon-demo-video).

## Actual event: verified November 8

[DevDay Exchange Community Hackathon](https://deepstation.ai/hackathons/vtl7ctbeihnikitvjwl3941h?tab=problem-statements): Codex Hackathon for Miami's Non-Profits. Selected challenge: **Grant applications and reports, each with its own rules**. The official page describes useful working software for South Florida nonprofits, and lists Codex, OpenAI API, and the OpenAI Agents SDK as acceptance criteria. Our build uses all three; the API/SDK path has real execution receipts.

The page says **submissions close November 8, 2026 at 4:45 p.m. EST**. It advertises $100 Codex and $50 API credits per person; whether a specific account has redeemed these or its remaining balance is not verified by this app.

The public **Judging Criteria** tab currently renders “Showing Judging Criteria,” without a scoring rubric or weights. The public **Submission** tab does not display a form. Exact fields, video length, and signed-in team status are therefore still unverified. Do not invent them or present general Devpost criteria as this event's published rubric.

## Ready and still to finish

- [x] All three core parts merged into public `main`; real live browser workflow passed.
- [x] Claim citations, missing-evidence gaps, word limits, exact cents, funder periods, approval invalidation, and real exports demonstrated/tested.
- [x] Desktop/phone visual checks completed; real-neighborhood theme variants and a guided first-use walkthrough prepared on `codex/miami-vice-themes`.
- [x] Real live SDK and live browser receipts committed. The new theme/guide checks run in fixture mode and add no API calls.
- [x] Concise demonstration script prepared; fixture video draft is labeled as such when recorded.
- [ ] Review the new design branch with the team, choose the presentation theme, and rehearse the actual demonstration.
- [ ] The team completes/validates registration and the signed-in submission form when ready.
- [ ] Confirm the actual required repository/demo/video links and their accessibility to judges. A Studio loopback URL with an SSH tunnel is a personal preview, not a public judging URL.
- [ ] Review narration and any video draft before uploading. No upload, registration, public deployment, external message, or contest submission is authorized by this document.

Use a clean fictional workspace for rehearsal. Reset only the explicitly selected demo database, never somebody else's working data. Keep `.env.local` and SQLite files out of Git. The current prototype is a local single-user workflow; future identity, hosting, and document-format support should be described as next steps.
