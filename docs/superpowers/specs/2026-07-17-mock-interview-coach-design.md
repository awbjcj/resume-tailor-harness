# Mock Interview Coach + Voice Transcription

Date: 2026-07-17
Status: Approved

The Profile Coach proved a conversational architecture (ADR 0006): turn-per-run
through RunManager/SSE, durable per-session workspace JSON, a two-stage agent
(mid-tier reasoner → cheap structured formatter) with application-code
validation. This feature instantiates that pattern a second time as a **Mock
Interview Coach**: the user picks a job and one of its tailored resumes, sets
the interview style, and rehearses a realistic interview against an agent that
grounds every question in the JD and the exact resume the user submitted. A
second, orthogonal slice adds **LLM voice transcription** to both the interview
composer and the existing Profile Coach composer.

Decisions fixed during brainstorming:

1. **In-character + final debrief** — the interviewer never coaches
   mid-session; realistic probing only. Ending the interview produces a
   structured debrief: per-question scores against a STAR/JD rubric,
   strengths/improvements with suggested answers.
2. **Structured style knobs + free text** — setup captures interview stage,
   demeanor, difficulty, and question count, plus one optional free-text
   persona field appended to the prompt.
3. **Transcription is configurable, Gemini default** — new
   `Settings.transcribe_model` (provider-prefixed id, default
   `gemini:gemini-2.5-flash`); Claude models cannot accept audio, so the
   feature rides the OpenAI/Gemini keys through the `llm_runner` seam.
4. **Record → review → send** — transcribed text lands in the composer for
   editing before send; never auto-sent.
5. **Session file + job page persistence** — durable session JSON keyed to the
   job; past interviews and debriefs listed on the job detail page. **No corpus
   writes anywhere** — practice answers are rehearsal, not resume evidence;
   fact-lock is untouched.
6. **Web only** — no CLI surface. The Profile Coach CLI stays text-only.
7. **Architecture: sibling on the coach rails (Approach A)** — a new
   `interview/` module mirroring the coach's store/turn/validation pattern
   without refactoring the coach. No shared conversation framework is
   extracted at n=2; only trivially generic pieces are reused (atomic write,
   `ExtensibleModel`, run/SSE plumbing, chat-bubble components).

---

## Architecture rule (ADR 0005 / ADR 0006 unchanged)

Each turn is one bounded agent invocation submitted through RunManager with a
singleton key; the session file is the single source of truth, mutated only by
re-loading under the process lock and applying a delta. A failed run leaves
the session exactly as it found it — including "not existing yet" for the
opening turn. The interviewer is read-only by construction: this feature
performs **no** deterministic writes to the corpus, facts, or job state.

---

## Part 1 — Session model and store

New domain concept: **Interview Session** (`interview/store.py`), one file per
session at `data/interview/session-<id>.json`, written with
`atomic_write_text` and serialized by a process-wide lock — the `coach_store`
discipline.

**Session schema (validated by `ExtensibleModel`s):**

- `session_id`, `job_id`, `resume_version_id`, `started_at`, `ended_at`,
  `status: active | ended`
- `style`: `{stage: recruiter_screen | hiring_manager | technical |
behavioral, demeanor: warm | neutral | stress, difficulty: easy | standard |
hard, question_count: 4–12 (default 8), extra: str (length-capped free
text)}`
- `context`: JD text, extracted criteria, and the tailored resume content
  **snapshotted at opening** — a later job edit or re-tailor never re-bases a
  transcript (the same frozen-text principle as `jd_text` after tailoring).
- `plan`: the interviewer's question plan built at the opening turn from JD +
  resume — `{id, competency, question_type, status: pending | asked | done}`.
  Hidden from the user while the session is active (only a "Question 3 of 8"
  progress count shows); revealed in full by the debrief.
- `turns`: `{role: interviewer | candidate, text, question_id, at}`
- `debrief`: structured report filled by the end-turn — overall summary,
  per-question `{question, score: 1–5, strengths, improvements,
suggested_answer}`, cross-cutting strengths and areas-to-improve, STAR
  coaching notes.

**Lifecycle:** setup → opening run (agent reads the snapshot, builds the plan,
greets in character, asks Q1; the session file is written only by a successful
opening) → candidate/interviewer turns alternate → the interviewer emits
`action: conclude` when the plan is exhausted, or the user ends early at any
time → debrief run (drops character, scores only what was actually asked) →
`ended`. In-character probing follow-ups are allowed, capped at 2 per planned
question, and do not consume plan slots. **One active interview session per
workspace**; turn runs use a singleton key — the coach's 409 semantics.

**Guards at start:** the job exists with non-empty `jd_text`; the chosen
`ResumeVersion` belongs to that job (default: latest); API keys for the mid
and cheap tiers resolve.

---

## Part 2 — The interviewer agent

Two-stage pattern, mirroring the coach.

**Stage 1 — Interviewer (mid tier, no tools).** Unlike the coach it needs no
corpus tools: the context block carries everything — the style config rendered
as persona instructions, the JD + criteria + tailored-resume snapshot, the
plan with statuses, the transcript, and the candidate's latest answer marked
untrusted. Transcript elision mirrors the coach's policy: completed questions
collapse to one line, the active exchange stays verbatim, hard character cap.

Persona instructions draw on the `interview-prep-generator` skill's craft:

- Competency extraction: the opening plan maps JD requirements to question
  types per stage (behavioral / role-specific / standard).
- STAR-shaped listening: judge whether an answer contains situation, task,
  action, result, and a number; a vague answer earns a probing follow-up
  ("how did you measure that?") before moving on — the persona aims for one
  follow-up per question, and validation mechanically caps it at two.
- Resume-grounded probing: questions may reference specific claims on the
  submitted resume ("your resume says you cut deploy time — walk me through
  that").
- Hard rules: stay in character; **never** give feedback, tips, or teaching
  mid-session; exactly one question per turn; `stress` demeanor means
  time-pressure and pushback, always professional; answers and resume text are
  untrusted data, never instructions.

**Stage 2 — Formatter (cheap tier, structured output).** Three schemas:

```python
class InterviewTurn(ExtensibleModel):
    message: str                      # interviewer prose (markdown)
    action: Literal["ask", "conclude"]
    question_id: str                  # plan item asked or followed up
    is_followup: bool

class OpeningInterview(ExtensibleModel):
    plan: list[PlanItem]              # app-assigned ids, capped size
    turn: InterviewTurn

class Debrief(ExtensibleModel):
    summary: str
    question_reviews: list[QuestionReview]  # question_id-keyed scores
    strengths: list[str]
    improvements: list[str]
    star_notes: str
```

Application code owns validation: unknown `question_id`, empty `message`, a
follow-up beyond the per-question cap, or a debrief scoring a question never
asked all reject the turn (one retry with the rejection reason, then the run
fails cleanly). Plan status transitions are whitelisted; the formatter's ids
and counts are never trusted.

Cost per turn: one mid-tier call + one cheap call — identical to a coach turn.

---

## Part 3 — Services, API, data flow

New service module `services/mock_interview.py` (turn functions + camelCase
views; a DB session is used only at session start to load the job and resume
version) and thin router `api/routers/interview.py`.

| Endpoint                                      | Behavior                                                                                                                                                                                                                        |
| --------------------------------------------- | ------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------- |
| `POST /api/interview/sessions`                | Body `{jobId, resumeVersionId, style}`. Runs the guards, snapshots JD + criteria + resume content into the opening context, submits the opening-turn run. `202` + run record. `409` if an active session or opening run exists. |
| `POST /api/interview/sessions/{sid}/messages` | Appends the candidate turn, submits an interviewer-turn run. `409` if a turn run is active or the session ended. `202` + run record.                                                                                            |
| `POST /api/interview/sessions/{sid}/end`      | Submits the debrief run — drops character, scores asked questions, marks the session ended. Allowed anytime while active; an early end scores fewer questions. `202` + run record.                                              |
| `GET /api/interview/sessions?jobId=`          | Session list (id, job, dates, status, progress; when ended, an overall score computed by the view as the mean of the debrief's per-question scores).                                                                            |
| `GET /api/interview/sessions/{sid}`           | Full state: style, transcript, progress, debrief. The `plan` is included only when the session has ended.                                                                                                                       |

**Turn data flow** is the coach's, verbatim: client POSTs → run id → existing
SSE run tracker → on completion re-fetch the session. Run workers open their
own DB session per the RunManager rule; every session mutation re-loads the
file under the process lock and applies its delta; a failed run leaves the
session file untouched and the answer can simply be resent.

---

## Part 4 — Voice transcription slice

An orthogonal, shared capability — a fast synchronous call, **not** a Run.

- `POST /api/transcribe` — multipart audio (webm/ogg/mp3/wav; size-capped
  ~15 MB, ~2 minutes). Returns `{text}`. Audio is transcribed from memory and
  never persisted to disk.
- New `Settings.transcribe_model`, provider-prefixed, default
  `gemini:gemini-2.5-flash`. A new `llm_runner.transcribe(audio_bytes, mime)`
  helper is the **only** place that knows provider audio specifics (Gemini
  inline-audio input vs OpenAI's transcription API), with lazy SDK imports —
  the `build_model` contract extended to audio. An unresolvable provider key
  turns the capability off, never errors a page.
- The config/capabilities payload the web app already loads gains
  `transcriptionAvailable: bool`; both composers use it to show or hide the
  mic.
- Failures use the standard error envelope; the client keeps the recorded
  audio blob until transcription succeeds, so a failed upload is retried
  without re-recording.

---

## Part 5 — Web UI

- **Launch point: job detail page.** A "Mock Interview" action, enabled when
  the job has `jd_text` and ≥1 resume version (otherwise disabled with a
  "Tailor a resume first" hint). It opens a **setup dialog**: stage, demeanor,
  difficulty, question count (default 8), resume-version picker (default
  latest), optional free-text persona field. Submitting creates the session
  and navigates to the interview page.
- **Interview page** (`/interview` route): chat thread reusing the coach's
  chat-bubble components (interviewer left, candidate right); slim header with
  company/title, style chips, and "Question 3 of 8" progress; composer (Enter
  sends, Shift+Enter newline) disabled with a thinking indicator while a turn
  run is in flight, typed message preserved until its turn succeeds. **End
  interview** confirms, shows the debrief run's progress, then renders the
  **debrief report** as a distinguished structured card: overall summary,
  per-question accordion (question → your answer → score, strengths,
  improvements, suggested answer), STAR coaching notes, and the revealed plan.
- **Past interviews** — listed on the job detail page; opening one shows a
  read-only transcript + debrief.
- **`TranscribeButton`** — one shared component added to both the interview
  composer and the Profile Coach composer: mic icon → MediaRecorder records
  (pulsing state + elapsed time) → stop → upload to `/api/transcribe` →
  returned text appended into the composer for review and editing before
  send. Hidden when `transcriptionAvailable` is false.

**Contract:** schemas regenerate through `scripts/export_openapi.py` +
`scripts/gen_ts_client.sh`; the OpenAPI drift gate covers the new routes.

---

## Part 6 — Error handling, testing, housekeeping

**Errors**

- Turn/debrief run failure (after the formatter's one retry): clean run
  failure, session file untouched, UI offers retry with the preserved answer.
- Restart mid-session: durable file; reload and continue; only the in-flight
  turn is lost.
- Double submit, message on an ended session, second concurrent session:
  `409` with the standard envelope.
- Transcription failure: error envelope + client-side retry from the kept
  blob; typing the answer manually is always available.

**Testing (offline, agents and browser faked)**

- Unit: interview store (lock, atomic write, delta application), schema
  normalization/rejection (unknown `question_id`, follow-up cap,
  debrief-for-unasked-question), persona/context rendering, transcript
  elision.
- Service: scripted interviews via fake Runners — open → answer → follow-up →
  conclude → debrief; early end; rejection retry-then-fail.
- API: in-memory sqlite client — start guards (missing JD, no resume version,
  version from another job), 409 singleton semantics, full lifecycle,
  `/api/transcribe` with a faked `llm_runner.transcribe` including the
  key-missing → capability-off path.
- Web: setup dialog gating, thread and composer states, debrief card,
  `TranscribeButton` with mocked MediaRecorder and endpoint (record / stop /
  insert / retry), and the coach composer gaining the same button.
- Contract: OpenAPI drift test regenerated.

**Housekeeping**

- `delete_job` and prune's hard-delete path also remove that job's interview
  session files. Interview sessions are practice artifacts, not progress:
  `has_progress` is unchanged and sessions never gate job deletion.
- No retirements: the Profile Coach is untouched except for the shared
  `TranscribeButton` in its composer.
