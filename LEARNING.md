# Learning log

Dated entries. For each session: concepts met, what clicked, mistakes worth remembering, open questions.

## 2026-10-10: Phase 0, planning and setup
- **MVP (minimum viable product):** the smallest version that proves the idea works for a real user. Scope is cut on purpose; the rest goes to v2.
- **Front end vs back end:** the front end runs in the user's browser (what they see and click). The back end runs on a server (files, secrets, calls to AI services). API keys live only on the back end, because anything in the browser can be read by the user.
- **Monorepo:** one repository holding both `frontend/` and `backend/`. Simple for a solo project; larger teams sometimes split them.
- **Environment variables and `.env`:** settings and secrets kept outside the code. `.env` is gitignored; `.env.example` is committed with empty values so anyone knows which settings to fill in.
- **OpenAI-compatible API:** a request format many AI providers accept. Writing to that format, with the provider chosen in `.env`, is how Lucy stays vendor independent.
- **Grounding:** making AI output depend on real sources. In Lucy the AI only suggests search terms; real APIs return the links.
- **Public repo:** anyone can read the code and the full history. A secret committed once stays in the history even after deletion, so `.gitignore` must be right before the first commit.
- **Privacy by design:** deciding what data a system may touch before building it (here: role-play and teaching audio only).
- Explain-back (to answer next session):
  1. Why must the Groq API key live in the back end and never in the React code?
  2. If we want to switch from Groq to a local model next year, what do we change, and what stays the same?
  3. Why does the further-reading feature not just ask the AI for "five good references"?
- Explain-back answers (2026-10-10, second session):
  1. Right conclusion, imprecise reason ("the code is public"). The real reason: front-end code is downloaded to and runs on the user's device, so anyone can read it with developer tools, even if the repo were private. Principle: the **trust boundary**; nothing on the user's side can hold a secret.
  2. Solid: change `.env` settings (URL, key, model), keep the code. Caveat added: a new provider keeps the app connected but not necessarily the same output quality, so re-test after switching.
  3. Half right. Correction: the AI does not search or propose sources at all; it only suggests search terms, and real APIs return real links. The reason is **hallucination**: LLMs produce plausible-looking references that may not exist, and "plausible" is the danger.
- AI-tool feature: `/resume` reopens past Claude Code conversations, filed by folder path (renaming the folder hides old chats). Verdict: use it for continuity, but keep `PROGRESS.md` as the real record, since it travels with the repo.

## 2026-10-10: Phase 1, front-end shell
- **Browsers run three languages:** HTML (structure), CSS (appearance), JavaScript (behaviour). React, TypeScript, Vite and Tailwind all exist to produce those three more easily.
- **Single-page application (SPA):** the page loads once; after that React redraws parts of it as state changes.
- **Component:** a function that returns part of the screen. The page is a tree of components (`App` contains `NotesEditor`, `Recorder` and so on).
- **Props and state:** props are inputs handed down by a parent (read-only); state is data a component remembers and changes, and changing it redraws the screen (`useState`).
- **One-way data flow (data down, events up):** shared state lives in the common parent (`App`), goes down as props, and changes come back up through functions passed as props (`onComplete={setRecording}`). Siblings never talk directly.
- **Controlled input:** the text box shows React's state and reports each keystroke; state is the single source of truth.
- **Derived values:** calculate what you can (word count, whether Generate is enabled) instead of storing a second copy that can drift (the BMI rule).
- **Side effects and cleanup (`useEffect`):** timers, storage and page changes happen outside drawing. The cleanup function stops them when they are no longer needed; without it they pile up (memory leak).
- **TypeScript union types:** `'idle' | 'recording' | 'paused' | 'done'` makes a typo a build error instead of a silent bug.
- **Design tokens:** colours defined once as named values; dark mode swaps the values, not the components. Same principle as `.env`: configuration vs code.
- **Dev server vs build:** `npm run dev` translates code on the fly for development; `npm run build` produces the plain files that get hosted. `localhost:5173` is "this computer, port 5173".
- **Accessibility:** labels for screen readers, keyboard focus that follows the user, status announcements (`role="status"`), and respecting "reduce motion".
- **Trust boundary again:** browser file checks are for convenience; the server must check again.
- Lessons from the build and the quality review:
  - **Supply chain:** the shadcn installer misread our import alias and installed an unrelated npm package (`cn`). Check what installers add to `package.json`.
  - **Filters break glass:** any CSS `filter` on a parent disables `backdrop-filter` blur inside it; the entrance animation now removes its filter when it ends.
  - **Hover is not touch:** a tap fires both hover and click, so the flashcard flipped and unflipped. Interactions must be designed for touch, mouse and keyboard.
  - **Stable function identity:** a function created inside a component is new on every render; when an effect or ref depends on it, wrap it in `useCallback` so it does not re-run.
  - **Undo beats confirm:** a one-click Clear got an "Undo clear" instead of an "Are you sure?" box.
- Retype: added the "Clear" button to the notes panel (conditional rendering, events up). Worked first time; two stray spaces in closing tags tidied in review.
- Explain-back answers:
  1. Recorder to GenerateBar: named one-way data flow correctly, but described the Recorder as "retrieving" info. Correction: it sends data up by calling `onComplete` (which is `App`'s `setRecording`); `App` re-renders and passes `recording` down as a prop.
  2. Missing cleanup: answered that pause would act like stop. Wrong way round: without cleanup nothing stops the old interval, so the timer keeps counting while paused and runs at double, then triple, speed after each resume. **Revisit.** (Strict Mode in development runs effects twice on purpose to expose this.)
  3. Hard-coded dark colours: answered "everything black and a white flash". Correction: the cost is maintenance and consistency; colours scattered across many files, so a palette change or a new theme means editing every component. Tokens change in one place (the formulary principle).
- AI-tool features: **Playwright** (scripted real-browser checks; caught four UI bugs before Rugimbana saw them; verdict: adopt, becomes end-to-end tests in phase 10). **Quality subagent** run in the background while feedback was written (parallel work).
- **Going back with git (revert vs reset):** the design upgrade was undone with `git revert --no-edit ef045ee`, which adds a new commit that reverses that one commit and leaves history intact. `git reset` would erase the commit and, since it was already pushed, need a force push that rewrites the public history. On a shared, pushed branch, use revert. One genuine bug fix from the reverted commit (removing the leftover blur filter) was re-applied by hand afterwards.

## 2026-10-11 to 2026-10-12: Phase 2, back-end skeleton
- **Client and server, HTTP:** the browser (client) sends a request (method, path, headers, body); the server answers with a response (status code, headers, body).
- **REST:** design an API around resources (nouns like `/api/sessions`) acted on by HTTP methods (verbs: `GET` reads, `POST` sends something new). An **endpoint** is one method plus one path.
- **Status code families:** 2xx success, 4xx the request was wrong (client's side), 5xx the server failed (our side). Lucy uses 200, 400, 413 (too large), 415 (wrong file type), 422 (well-formed but unusable).
- **Multipart upload:** one request split into labelled parts (notes, then each file), separated by a boundary the browser chooses. That is why we never set `Content-Type` ourselves with `FormData`.
- **CORS and the same-origin policy:** a different port counts as a different origin. The browser reads the server's `Access-Control-Allow-Origin` reply before letting a page read the answer. Simple requests go straight through; JSON requests first send a preflight (`OPTIONS`).
- **Uvicorn, ASGI, FastAPI:** Uvicorn listens on the port, ASGI is the standard hand-over, FastAPI is where the routes live.
- **Middleware as an onion:** each request passes through layers before reaching the route. In FastAPI the layer added last is the outermost. CORS sits outside the size limit so even a 413 carries CORS headers.
- **Pydantic:** declare the shape and limits of data; FastAPI rejects anything else with a 422 before our code runs. Same tool will check the AI's JSON in phase 4.
- **Magic numbers (file signatures):** identify a file by its content (`%PDF-`, `PK` for zip), not its name. A .pptx is a zip; we read its table of contents for `ppt/presentation.xml` without unpacking it (no zip bombs, no zip slip).
- **Defence in depth:** browser checks for convenience, server checks for safety, and a size limit that counts bytes as they arrive because the client's declared size can lie.
- **Discriminated union (`SendState`):** each status carries its own data; TypeScript only lets you read `receipt` after checking the status is `'received'`.
- **Tests:** `pytest` with `TestClient` calls the app in-process. Tests caught a corrupted file in under a second during the build.
- Warm-up (effect cleanup, revisited from phase 1): right this time. Without cleanup the old interval keeps running, so pause does not pause and each resume adds another timer.
- Retype: `Limits` model and `GET /api/limits`. Worked first time. Style note: Python (PEP 8) puts two blank lines between top-level functions and classes; fixed in review.
- Explain-back answers:
  1. Renamed `virus.exe`: right idea (content is checked, not the name) and right family (4xx). Sharper: the browser check passes it (it only reads the name); the file does reach the server, lands in a temporary file, fails the signature check, is refused with **415**, and is deleted. "Rejected" is not "never uploaded".
  2. `curl` and CORS: **wrong.** CORS does not stop curl. CORS is a rule the browser enforces to protect its user from malicious websites reading other sites' answers with the user's browser. Tools outside a browser ignore it. The server must protect itself (our checks now, an access code in phase 10). **Revisit.**
  3. 415 vs 500: right. 415 means the request was wrong; 500 means our code failed on it (a bug for us to fix).
- Data down, events up: not sticking yet. Re-explained with the ward chart analogy (App holds the one chart; children get read-only copies and call App to change it). **Revisit** with the check question about a word count in the Header.
- AI-tool feature: **`/security-review`** skill. Found nothing exploitable; it compares committed changes against GitHub, so it had to be pointed at the staged changes. It skips denial-of-service and correctness on purpose, so it complements the Quality reviewer (which found a real 500 bug). Verdict: adopt for phases touching inputs, secrets or access (3, 6, 10).

## 2026-10-12: Phase 3a, recording
- **Microphone permission and secure context:** the browser asks the user, not the website, and only on https or localhost pages.
- **`await` and Promises:** a Promise is an IOU for an answer that comes later (for example, the user clicking Allow). `await` pauses that one function until the answer arrives; the rest of the page keeps running.
- **Callbacks:** functions handed to the browser to call when something happens (`ondataavailable`, `onstop`).
- **MediaRecorder and Blobs:** the browser's tape recorder delivers 1-second chunks; Stop glues them into one in-memory file (a Blob).
- **Container vs codec, bitrate:** envelope (WebM, MP4) vs the language inside (Opus, AAC). 32 kbps keeps speech clear: about 14 MB an hour (measured 18 KB for 5 seconds).
- **RMS level meter:** centre the samples on silence (128), square, average, square root. With the mean at zero, RMS is the standard deviation of the wave.
- **Custom hooks:** a `use...` function that bundles state and effects. The engine (`use-audio-recorder.ts`) is separate from the dashboard (`Recorder.tsx`).
- **State vs refs:** state is the whiteboard (changing it redraws the screen); a ref is a pocket notebook (kept, but no redraw). Live browser objects go in refs.
- **Object URLs:** a temporary address for an in-memory file, like a cloakroom ticket; revoke it in the cleanup.
- **Timestamps vs counting ticks:** counting timer ticks loses time around pauses and in background tabs; subtracting timestamps does not.
- **Race conditions:** two actions overlapping in an order nobody planned (upload during the permission prompt; double-clicking Stop). The fix: check the current state before acting.
- **Single source of truth, applied:** the Recorder no longer keeps its own "done" flag; the recording lives in `App` and comes down as a prop.
- Explain-back answers:
  1. Refs vs state: right (the timer must redraw every second; the stream only needs to be kept).
  2. Stop to chip: events up right, but described App as "throwing up a function". Correction: App handed `onChange` down at the start; Stop calls it (up); App updates its chart and passes the recording down to GenerateBar, which draws the chip. Memory hook: "down go data and phone numbers, up go phone calls." **Revisit.**
  3. Race condition: described as acting before permission. Correction: the problem was two actions overlapping (upload finishing while the microphone was starting). Named the term; fix is checking the current state before acting.
- No retype this phase (kept rare on purpose); the 3b polling loop is the next candidate.
- AI-tool feature: **hooks** (a standing order for Claude Code). After any back-end Python edit, the tests run automatically; silent on success, reported on failure. Proven to fire. Verdict: adopt. Review with `/hooks`.
- The Quality reviewer found two real microphone bugs (both race conditions) that the browser tests had missed; tests only check the paths you think of.

## 2026-10-12: Phase 3b, understanding
- **202 Accepted and background jobs:** the server answers at once with a job number ("received, still working") and does the slow work afterwards, like a lab specimen number.
- **Polling:** the browser asks "is it ready yet?" every 1.5 seconds. The alternative, being told when it is ready (streaming or push), comes in phase 5.
- **Threads and locks:** jobs run on several worker threads sharing one list of jobs; a lock makes them take turns, like nurses sharing one pen for one chart.
- **Provider layer and SDK:** one door to outside AI, using the `openai` library pointed at any OpenAI-compatible provider from `.env`. Transcription can use its own provider. `SecretStr` hides the key from logs.
- **Translating errors:** technical failures become plain words for the student; the technical cause is logged for the operator, never the student's content.
- **Text extraction:** pypdf and python-pptx, including tables, grouped shapes and speaker notes. Scanned PDFs have pictures of words, not text, so Lucy warns. Limits on pages and unpacked size because files come from strangers. python-pptx reads XML with entities switched off (no XXE).
- **Data minimisation:** keep the least for the shortest time. Files deleted when the job ends, leftovers swept at startup, results forgotten once collected. The privacy notice must match what the code does.
- **Test stand-ins (fakes, mocks):** a fake transcription function returns a fixed sentence, like a simulated patient in an OSCE. Real calls in tests are slow, unreliable, use the free quota and send data out; the first test run did reach Groq by mistake, which the hook's slow run exposed.
- **AI errors are real:** the first live transcript turned "nebulised" into "nebulasts" in a drug instruction.
- Explain-back answers:
  1. 202 vs 200: right.
  2. Copying uploads: half right. FastAPI deletes the uploads when the request ends, which is before the job even starts; the job needs its own copy to work on afterwards, and deletes that copy when it finishes.
  3. Test stand-ins: not answered (tired). Answer recorded above. **Revisit.** Raised instead a good product point: the student should be able to edit the transcript before the AI uses it (human in the loop). Adopted as the first item of phase 4.
- Retype: done by Claude at Rugimbana's request (tired): polling now tolerates up to two dropped checks in a row; tested by cutting the connection on purpose (2 dropped: continues; 3 dropped: clear message).
- AI-tool feature: the hook proved itself (caught the 200 to 202 change at once; its slow run exposed tests calling Groq). Review agents ran in parallel in the background.
- Process slip (Claude): two progress-file edits silently matched nothing (the phase 3a status line, then the first 3b close). Fixed; edits to these files are now checked after writing.

## 2026-10-13: Phase 4a, edit before writing
- **Human in the loop:** a person checks the AI's work before it is used (a senior signing off an intern's drug chart). The student corrects the transcript and slide text; the AI writes from the corrected version.
- **Controlled component:** the text box shows only what comes down as `value` and sends every keystroke up through `onChange`. Remove `onChange` and typing does nothing.
- **Lifting state up / data down, events up, in real code:** the draft lives in `App`; the panel gets a copy and phones changes up. `App` keeps Lucy's original reading unchanged next to it.
- **Derived state:** "corrected by you" is worked out by comparing draft and original each time (like BMI from height and weight), never stored, so it cannot go out of date and Undo needs no extra code.
- **Immutable update and reference equality:** `slides.map(...)` builds a new list with one slide replaced; React notices a change by "is this a different object?", not by reading every word. The same idea tells Lucy that the slides or recording changed after reading (`sendState.slides !== slides`).
- **State updates are applied later, not on the spot:** `setState` notes the change and React redraws afterwards. Moving focus straight after closing the panel failed because the Generate button was still disabled; `flushSync` redraws first. Rarely needed; the principle is fundamental.
- **Protecting the student's work:** confirm before losing corrections (close, read again), but only when there are corrections, so warnings keep their meaning.
- Retype: `setSlideText` (immutable update). Correct and compiled first time.
- Explain-back: Rugimbana asked for the answers to be explained instead (end of weekly AI quota). Answers given: (1) stand-ins make tests reliable, fast, free of quota and private; they cannot tell whether the real AI behaves (valid JSON, sensible content), so live checks by hand remain; (2) without `onChange`, typing does nothing because the box only shows what comes down; (3) a stored flag goes stale (type then delete a word), a comparison cannot. **Revisit all three**, plus the 3b stand-in question (now explained, not yet answered).
- The Quality reviewer again found real bugs that 16 browser checks missed: focus lost on close, and a dead end for notes-only sessions. Tests check the paths you think of; review finds the others. Browser check extended to 24 checks, all passing.

## 2026-10-13: Phase 4b, the generator
- **Tokens:** the AI reads word-pieces, not words (about 3/4 of an English word each; medical words cost more). Input, output, reasoning and quota are all counted in tokens.
- **Context window vs rate limit:** gpt-oss-120b can hold about 131,000 tokens, but Groq's free tier allows 8,000 tokens a minute, in and out together (the pharmacy that could dispense a ward's drugs but lets you collect 8 boxes a minute). Measured: a pack costs about 2,900 tokens besides the material, so about 2,475 words (roughly 18 minutes of talk) fit. Read from Groq's reply headers, not guessed: 1,000 requests a day, 8,000 tokens a minute, same for all three candidate models.
- **Temperature:** how adventurous word choices are; 0.3 for steady medical wording.
- **Structured output:** the AI fills in a form (JSON schema from the `PackDraft` Pydantic model, `strict`), then Pydantic checks it again. A broken answer gets one more try. Two schemas: what the AI fills in (`PackDraft`) and what the browser receives (`StudyPack`, the AI's work plus Lucy's checks).
- **Hallucination and grounding:** a language model predicts plausible text; it does not look things up. Every item carries a quote, and Lucy checks the quote is really in the material ("show me where in the notes it says that"). "Not found" means "check this one", not "wrong". First live run: 2 of 13 flagged, both stitched quotes; after a prompt fix, 13 of 13 and then 15 of 15 grounded.
- **Maximums, not minimums:** "exactly 10 flashcards" would force invention from three lines of notes.
- **Prompt injection:** material is untrusted text; it sits inside tags, the instructions say to treat it as data, and our own tag names are removed from it. Real impact here is low (no tools, no secrets, schema-bound output shown as text), but hidden text in a third-party slide deck could steer content.
- **Reasoning models:** gpt-oss thinks silently first, and that costs tokens ("Say OK" used 100); `reasoning_effort` low.
- **Vendor independence includes limits:** model, tokens per minute and reasoning effort are all in `.env`.
- **The Quality reviewer's clinical catch:** the first grounding check ignored symbols, so "5 µg" matched "5 g" (a millionfold dose difference) and "< 92%" matched "> 92%". Fixed with Unicode normalisation (NFKC) that keeps symbols as words. Also fixed: a race (closing the panel during a write let an abandoned pack appear later; each write now has a number and only the latest counts), links filtered out of the pack, a 2 MB body limit for text requests, only the "broke the form" error is retried, error bodies never logged (they can echo the student's material), options shuffled because models favour some answer positions.
- Retype: none this half (kept rare; the quota reset was close).
- Explain-back answers:
  1. Why a 131,000-token model refuses about 2,500 words: half right. Input and output do share the budget, but the deciding limit is the free plan's rate limit (8,000 tokens a minute), not the context window (what the model can hold). Keep the two terms apart. **Revisit.**
  2. "At most 10", not "exactly 10": right. A forced count pushes the AI to invent.
  3. "Not found in your material": right spirit. Sharper: the item's quote could not be found word for word in the student's material, so the item is unverified, not necessarily wrong (it may be paraphrased, stitched or invented); check it against notes or a trusted source before relying on it. The term is grounding.
- AI-tool features: the hook caught the new `pack` field at once; the Quality reviewer, asked to cover security too, found 16 items including a must-fix race and the dose-unit bug. A memory note now records that `git -c http.version=HTTP/1.1 push` gets past this network's connection resets.

## 2026-10-13: Phase 5, the results screen
- **Local state:** which flashcard shows and whether it is flipped live inside the flashcard component; only shared data (the pack, the corrections) lives in `App`. State lives in the lowest component that needs it.
- **Accessible primitives:** Radix Tabs gives the roles (`tablist`, `tab`, `tabpanel`) and arrow-key movement; we only style it. By default it removes a hidden tab's contents, which would wipe quiz progress, so the tabs stay mounted and are hidden instead (`forceMount`).
- **The `key` as a reset button:** a new key tells React "this is a different thing, start fresh": each new pack (`key={run}`), each flashcard, and the step timer (`Elapsed`). Lint flagged the first timer, which reset itself with `setState` inside an effect; the key is the clean way.
- **3D transforms:** the card turns 180 degrees around its vertical axis; each face is hidden when it faces away (`backface-hidden`).
- **Live regions:** hidden text that screen readers announce when it changes ("Correct.", "Card 3 of 8. Question: ..."). Changing a focused button's label is often not announced, so the card has its own live region.
- **Focus management:** when something the student is using disappears (the old card, the old question, the score screen), focus has to be handed to its replacement, or keyboard and screen reader users are dropped at the top of the page. A `disabled` button also drops focus; `aria-disabled` keeps it.
- **One measure, shared:** the meter first showed words while the server decided in characters, so "2,000 of 2,475 words" was still refused. Now characters decide on both sides and are shown as words at one rate (6 characters a word, measured), with room kept for the server's own tags. The honest limit is about 1,883 words, roughly 15 minutes of talk (the 2,475 recorded for phase 4b was too generous).
- **Polling vs streaming:** polling (asking every 1.5 s) vs Server-Sent Events (the server tells you) vs WebSockets (two-way radio) vs streaming tokens (watching the text being typed). Lucy keeps polling: a pack takes about 6 seconds, polling works on any free host and survives dropped connections, and a structured JSON answer is useless until complete and checked. Streaming fits phase 8, where a chat reply is free text.
- **Network-level stand-ins:** Playwright answered `/api/packs` itself with a saved pack: no AI quota, the same result every time. Same idea as the back-end stand-in, one layer out.
- The Quality reviewer found a must-fix crash the browser checks had missed: a pack with no flashcards blanked the page, and thin material gives exactly that. Also focus lost on card and question changes, a faded explanation below contrast guidelines, and a pulse that kept blinking for people who ask for less motion. All fixed and checked in the browser.
- Explain-back: losing quiz progress on a tab switch is a state problem: right. The progress is state inside the Quiz component; when Radix removed the hidden tab, the component and its state were destroyed. Rule: unmounting destroys state, hiding keeps it. Context window vs rate limit (revisited from 4b): understood. Follow-up question from Rugimbana, "is there a `/clear` for our model?": no need, because each API call is stateless; the model remembers nothing between requests, so nothing builds up. A chat resends its history every turn, which is why Claude Code has `/clear` and why the phase 8 chat will need its own trimming. Also: a bigger context window does not prevent hallucination, and models attend less to the middle of long inputs ("lost in the middle").
- Retype: none (kept rare).

## 2026-10-13: Phase 5c, an overview and what the pack leaves out (Rugimbana's idea)
- **The product risk:** a confident summary that silently leaves out something the teacher stressed. Rugimbana raised it; it is the main clinical concern for the product.
- **Overview paragraphs** read the session as a whole, but prose has no quotes, so it is labelled as not checked. The first live overview said "high-flow oxygen" where the consultant said "oxygen to keep saturations 94 to 98 percent": unquoted prose drifts. The prompt now asks for the material's own wording for doses, numbers and drug names; the next run kept it.
- **Coverage check:** every teaching point now carries a quote too. Lucy cuts the material into passages of about 40 to 80 words and lists the passages no quote comes from, for the student to read. Like a handover checklist: not "trust the summary" but "here is what it did not mention". Honest wording: "does not quote", and "a rough check: a quoted passage can still hold points the pack leaves out".
- **Over-reporting is the safe error:** showing a passage the student did not need costs a minute; hiding one they needed could cost marks or a patient. The review found three ways coverage hid things (a wrong count, no maximum passage size so one quote could cover a whole unpunctuated transcript, and repeated phrases covering unrelated passages); all fixed, and grounding and coverage now share one function (`_locate`) so they cannot disagree.
- **Measure, then budget:** the longer answer costs about 3,950 tokens besides the material (live run), and about 6,100 in all near the limit. The limit drops to about 1,591 words (roughly 12 to 13 minutes of talk).
- A pack has at most about 25 quotes, so in a long session more passages will always be listed as not quoted. Acceptable: it errs towards showing more.


## 2026-10-13: Phase 6, credible further reading
- **The rule made real:** the AI only suggests search terms; links come from StatPearls, PubMed, Wikipedia, five YouTube channels, and the search pages of Radiopaedia and MSD Manuals. Two locks on every link: built from a checked id (digits for PubMed, 11 characters for YouTube), then accepted only if it is https on an allowed host (defence in depth).
- **The pharmacy analogy:** the browser never phones suppliers; it asks Lucy's server, which orders from approved suppliers only (allow-list), keeps the account numbers private (API keys stay on the server), keeps common items on the shelf for a day (cache with a TTL), respects each supplier's limits (rate limits, quotas), and still delivers when one supplier is out (graceful degradation).
- **GET vs POST:** a lookup that changes nothing is a GET, with the term in the address (URL-encoded: a space becomes `%20`).
- **async and the event loop:** like a nurse who sends off bloods and does other jobs instead of waiting at the analyser. `asyncio.gather` sends all six lookups at once: the wait is the slowest (about 2 s), not the sum.
- **Caching:** answers kept 24 hours, at most 500 of them (anyone can send any term), and answers with a failed source are never kept.
- **Rate limiting from our side:** a numbered-ticket queue spaces NCBI calls 0.33 s apart; a ticket more than 6 s away is refused at once, so a rush cannot block everyone after it.
- **Keys in headers, not addresses:** addresses end up in logs and error messages. The web client logged every address it called, so its logger is now kept to warnings (and a test checks it).
- **Data must not become instructions:** NCBI's automatic term mapping read "peak" as an author and "flow" as the journal Flow. Tying every word to a field fixed it; the same idea as preventing SQL injection.
- **YouTube catalogue:** YouTube's search costs 100 quota units a call for one channel (500 a term, 20 terms a day); reading the five upload lists costs about 80 units a day, then searching our own copy is free. Pagination (`nextPageToken`), a background task that refreshes daily, and an atomic write (temporary file, then one rename).
- **Matching, and precision vs recall:** topic words must appear, angle words ("acute", "management") only raise the score. Precision is like positive predictive value, recall like sensitivity: Lucy chose precision, because an off-topic video in a demo costs trust, and the other sources cover what it misses. TF-IDF (rare words weigh more) was tried and dropped: in 3,500 titles "management" is as rare as "asthma". Tune on real data: unit tests passed while the first version failed on the real catalogue. Word matching cannot know synonyms; embeddings (phase 8) can.
- **Stand-ins one layer out:** `httpx2.MockTransport` answers at the HTTP level, so the real parsing code runs and only the internet is fake.
- **Front end:** the lookups live in `PackView` (`useReading`); `FurtherReading` only shows them and reports clicks up (data down, events up). The first lookup starts from the tab click, not an effect: the linter flagged setting state in an effect, and nothing is fetched for a tab never opened.
- **Bugs that taught something:** stemming cut "status" to "statu"; a module and a variable both named `cache` (the test hook caught it); a script named `inspect.py` hid Python's own module (shadowing).
- Retype: skipped at Rugimbana's request.
- Explain-back answers:
  1. Why a catalogue: right idea, wrong word. It is about YouTube **quota units**, not tokens (tokens belong to the AI model; rate limits are requests per second or minute). **Revisit.**
  2. Precision over recall: the trade is right; missing were the why (an off-topic video costs trust, like a false positive) and what covers the cost (the other sources).
  3. One source fails: right that the others still answer and the student sees which failed. Corrections: an answer with a failure is not cached at all, and Try again does work (the review's must-fix made the browser forget the term so it asks the server again). **Revisit.**
- AI-tool features: background subagents in parallel (the Quality review and the security review ran side by side; verdict: adopt for every close-out). The post-edit test hook caught the `cache` naming clash within seconds.

## 2026-10-13: Phase 7, study packs saved in the browser
- **Client-side storage and data ownership:** packs live in the student's own browser, like a patient-held record. Nobody else can read them and the server holds no copy; the cost is that clearing browsing data or a private window loses them. Export is the photocopy.
- **localStorage vs IndexedDB:** localStorage is a notepad (small, text only, instant), right for the notes draft. IndexedDB is a filing cabinet (large, whole objects, works in the background), right for packs. `idb` is a 1 KB wrapper that makes IndexedDB's older interface pleasant.
- **Object store, key, index:** a store is a drawer of records; the key (`id`) finds one record; the index (`by-saved`) keeps them sorted by date, so "newest first" needs no sorting.
- **Transactions:** all or nothing. An import writes every pack in one transaction, so a full disk part way through leaves nothing half-imported.
- **Schema versions and migrations:** the database has a version (its drawers and indexes); each record has a `format` (its shape). When either changes, an upgrade step converts what browsers already hold, in order.
- **Untrusted files:** an import is someone else's data, like an upload. Zod (Pydantic for TypeScript) checks every field and size, drops unknown fields, and checks each pack on its own so one damaged pack does not block a backup. React shows all text as text, so a file cannot run code in the page.
- **Trust does not travel with a file:** a file can claim "found in your material" for an invented quote. Lucy repeats the server's grounding check against the material inside the file, and may only lower the claim, never raise it. Imported packs are labelled.
- **Code splitting:** Zod added 37 KB (compressed) to every page load for a rarely used button, so it now loads only when the student presses Import (`import()` at the click).
- **Debouncing:** the notes draft is written half a second after typing stops, not on every keystroke, plus once more as the page closes (`pagehide`). The `storage` event keeps two tabs in step.
- **Separating "what is shown" from "what is happening":** the shown pack is now its own state, so pressing Generate again no longer wipes the old pack before the new one exists.
- **Reference equality, reused:** the leave-page warning knows a recording or corrections exist only in memory by comparing them (`!==`) with what the last saved pack was written from.
- **Supply chain:** the newest Zod was a day old; versions at least two weeks old were pinned exactly, since brand-new releases are where hijacked packages tend to appear.
- **First front-end unit tests:** Vitest with `fake-indexeddb`, a stand-in database in Node; the same idea as the back-end stand-ins.
- Reviews: the Quality reviewer found that the status line could go unheard by screen readers (a live region hidden while empty) and that "Delete all" left the notes behind on a shared computer; both fixed. The security review found nothing high or medium; three of four low findings fixed (quote re-check, notes in Delete all, imported search terms held to the generator's rules). The fourth (a forged file claiming the id of a pack not yet imported) needs someone who already holds your export; left on purpose.
- Claude's test slip: a browser check passed too early because "Saved in this browser" also matched the privacy notice's new sentence. Exact text matching fixed it. A test that passes for the wrong reason is worse than one that fails.
- Walkthrough and explain-back: a short beginner summary was given at Rugimbana's request; the full walkthrough and the explain-back answers are for the next session.

## 2026-10-17: Learning session 1, the whole map
- **The anchor analogy:** the browser is the ward, Lucy's server is the lab in another building, the API is the lab's test menu, a request is the form, a response is the result slip, JSON is the standard result format. Groq is the reference lab: when Lucy's server asks Groq, Lucy is the client. Client and server are roles, not machines.
- **Seen live:** `GET /api/limits` answered `200 OK` with a JSON body; `/api/limit` (no "s") answered `404 Not Found`, still as JSON.
- **Predictions:**
  1. Misspelled path: right (a 4xx, exact match). Correction: `limits` is part of an address (a path), not a variable.
  2. Server limit changed to 3, page untouched: right conclusion (the page still says 5, the server refuses on Generate with 422), half-right reason. The slide box does not ask the server; it keeps its own copy (`MAX_FILES = 5` in `SlideDropZone.tsx`). Only the word meter asks `/api/limits`. Led to two fundamentals: **never trust the client** (page checks are a courtesy, server checks are the safety) and **single source of truth**. A real design gap, logged for phase 8.
- **The journey of one Generate click:** stage 1 Read (`POST /api/sessions`, 202 with a job ID, polling `GET /api/jobs/{id}` every 1.5 s, Whisper, uploads deleted), the student corrects the text, stage 2 Write (`POST /api/packs`, 202, polling, the LLM fills a strict form, Lucy checks it), then the pack is shown and saved in IndexedDB.
- **Explain-back answers:**
  1. Server restarts while the page polls: answered 5xx. Corrected: a status code describes the one request it answers, not the job's history. While the server is down there is no answer at all (no status code; the page tries up to three times, in case of a Wi-Fi blip). Once it is back, it is healthy but its whiteboard (jobs in memory) is wiped, so it answers **404**, and the page says "Lucy's server restarted before it finished. Please send again." 5xx would mean the server broke while answering that request. **Revisit in session 3.**
  2. Where the material leaves the laptop: right that it goes to the AI provider and that this is why rounds are role-played. Missing: it leaves earlier, at step 1, to Lucy's own server (the same laptop now, someone else's computer once hosted), and search terms go to PubMed, Wikipedia and YouTube. Nuance: the model does not learn from a request as it answers; the risk is the provider keeping, logging or later training on what it receives, plus consent and data protection law (third party, no agreement in place).

## 2026-10-17: Learning session 2, the browser side (React)
- **Map from memory** (opening exercise): the three places, the two stages, the lab checking the AI's answer before the ward sees it, JSON as the common language, and IndexedDB for privacy were all there. Missing: the wire (POST, 202 with a job ID, polling GET returning 200). Corrected: the step between stages is a correction step, not only a green light; "every stop deletes" holds only for the stops we control (Groq's retention is Groq's policy, hence role-play only); IndexedDB files finished packs with their material, not requests. Implicit and right: the browser never talks to Groq, because the API key must stay on the server.
- **Concepts:** React as declarative drawing (the self-printing obs chart), components (form templates), props (read-only, handed down), state (a component's memory; a change means a redraw), JSX, data down and events up (followed through the theme button: `App` → `Header` → `ThemeToggle` and back), lifting state up, controlled components, derived state.
- **Predictions:**
  1. A do-nothing `onThemeChange`: right, nothing changes. Sharpened: the state lives in `App`, not in a theme component; the icon does not flip either, since it is drawn from the prop; the call does go up, nobody answers.
  2. Why `notes` lives in `App`: right, and it is the named pattern "lifting state up". The other half: no higher than needed (`cleared` stays in `NotesEditor`).
  3. Deleting `onChange` from the notes box: right, typing shows nothing.
  4. A stored word count: right instinct, wrong example (a paste does fire `onChange`). The real failures are the other doors the notes come through: Clear, Undo clear, a reload restoring the draft, another tab, Delete all. Also met: premature optimisation.
  5. Bonus (`MAX_CHARS = 20000` in `NotesEditor.tsx`): described what it does, missed that it is a second copy of the server's notes limit, the same drift as `MAX_FILES`. Logged for phase 8.
- **Explain-back answers:**
  1. Props vs state: state answered well (owned by the component, changes, triggers a redraw); no example given. Props: right that they come down and cannot be changed, but the example had it backwards. `App` does not instruct `ThemeToggle` to change the theme; it tells it the current theme and hands it a phone number, and `ThemeToggle` asks `App` to change it. Props are information, not commands.
  2. From a keystroke to the counter: right shape (event goes up to `App`, a state change, React redraws). Two corrections: nothing is automatic, `App` deliberately handed down the phone number (`setNotes`); and no component changes a "count" state, because the count is derived and recalculated as the new notes flow down. The letter itself appears only after the round trip. **Revisit at the start of session 3.**

## 2026-10-18: Learning session 3, across the wire
- **Warm-up (keystroke trace):** much better than the day before: the count is recalculated on the redraw (derived), in the right order. Slip: the `notes` state lives in `App`, not in the notes editor. The "a" on screen comes from `App`'s state, flowing down as the box's `value` prop.
- **Concepts:** HTTP as an agreed format (SBAR); request line, headers (the envelope's labels), body (the letter); `Content-Type`; GET (reads, safe to repeat) vs POST (acts); PUT, PATCH, DELETE; REST (nouns in paths, verbs as methods); status-code families and the practical rule (4xx change the request, 5xx retry later, 429 wait); exponential backoff; JSON vs multipart (binary files, base64, the sample bag with sealed pockets, the boundary); URL encoding; origin, same-origin policy, CORS, preflight, max-age; why CORS was met on purpose (no proxy).
- **Seen live with `curl`:** a raw request and response; `GET /api/packs` 405; empty notes 422 (Lucy's rule) vs `{"notes": 5}` 422 (automatic shape check); preflights from the allowed origin (200 with `access-control-allow-origin`) and a stranger (400 "Disallowed CORS origin"); the stranger's plain `curl` GET still answered 200.
- **Seen live in Edge's Network tab** (Rugimbana, notes-only Generate): `sessions` POST 202, one Read poll, `packs` twice (OPTIONS 200, then POST 202), four Write polls (predicted 6 s / 1.5 s = 4, measured 4), `reading?term=peak%20flow%20measurement`. Extras explained: `api.ts` is the page downloading its own code; `limits` twice because of StrictMode in development; a Google Fonts (Mulish) request that nothing in Lucy makes, most likely a browser extension (check the Initiator column).
- **Shown to a classmate** the same day: she found it useful. Showing early to target users is user research; noted to keep a line of such feedback in PROGRESS.
- **Predictions:**
  1. Groq answers 429: right on both counts. The roles flip (Lucy is the client, so it is Lucy's "fault"), and wait then retry. Lucy does it in two layers: the `openai` library retries twice with backoff, then the student is told to try again in a minute (the limit is per minute).
  2. Status codes: `DELETE /api/packs` 405 right; `GET /api/limits` ten times, all 200, right (and Lucy has no rate limit of its own yet: phase 10); `GET /api/jobs/hello` predicted 404, actually 422, because the ID's shape is checked before any lookup ("that is not a lab number" vs "no record of that number").
  3. Network tab rows: polls reported as 202 and `packs` as POST 200; corrected (polls are 200; the two `packs` rows are OPTIONS 200 and POST 202), then confirmed by Rugimbana.
  4. Writing again within 10 minutes shows an OPTIONS row again: predicted yes, actually no, because `access-control-max-age: 600` lets the browser remember the permission (unless "Disable cache" is ticked).
- **Explain-back answers:**
  1. "CORS protects the API?": right shape ("yes and no"; the API can still be reached directly). Refined: CORS protects the visitor, not Lucy's data, and it is a sign obeyed by honest porters (browsers), not a lock; the locks are the phase 10 access code and rate limit.
  2. Why two `packs` rows and one `sessions` row: answered as "a serious test needs checking". Corrected: the trigger is the form type (JSON is non-simple; multipart is what old web forms send), and the browser (the porter) phones ahead, not the lab. **Revisit at the start of session 4.**
- Rugimbana asked for each concept to be placed in general engineering too, not only in Lucy; "Beyond Lucy" added to the session format in `AGENTS.md`, starting with a general paragraph on CORS.
