# QSENTINEL — The Complete Guide (In Plain Words)
### Everything you need to understand, build, and present this project

**Problem Statement:** PS-141 — Quantum-Inspired Cyber Threat Detection for Digital Signature Security

---

## 1. What is QSENTINEL? (The 30-Second Version)

Imagine a bank has a super-secure vault door (that's the **quantum digital signature protocol**, called QS-L). The door itself is mathematically proven to be unbreakable in the normal sense — nobody can forge the key.

But here's the thing: even a perfect lock can't tell you if someone is *behaving suspiciously* around the vault over time — jiggling the handle a bit too often, showing up at odd hours, or the door mechanism slowly wearing out in a weird pattern.

**QSENTINEL is the security camera and analyst watching the vault, not the lock itself.**

- It **watches** every transaction (called a "session") going through the quantum signature system.
- It **never touches the lock** — it cannot open, close, delay, or interfere with the door's own decision to accept or reject a signature.
- It **raises a flag for a human security team (SOC)** when something statistically looks "off," and writes everything down in a tamper-proof logbook.
- It uses **plain statistics and math**, not Artificial Intelligence. There is no "learning," no training data, no neural network anywhere in it. This is a deliberate and important design choice.

In one sentence: **QSENTINEL is a non-AI, statistics-based monitoring layer that watches a quantum digital-signature system and quietly flags suspicious behavior for humans to investigate — without ever having the power to block a legitimate signature.**

---

## 2. The Problem, Explained Simply

### 2.1 What is the underlying system?

The system QSENTINEL watches over uses **quantum teleportation** to send a digital signature. In simple terms:
- A "message" is encoded onto a quantum particle (a qubit).
- Instead of sending that particle directly, it uses a trick called teleportation (using a pair of "entangled" particles) to recreate the message at the other end.
- The receiving side checks the signature using a rule that's already mathematically proven secure (this proof is *not* something QSENTINEL creates — it's inherited from existing published research on the QS-L protocol).

### 2.2 Why do we need something extra, if the lock is already unbreakable?

Because a lock only answers ONE narrow question:

> **"Does this specific transcript follow the rules right now?"**

It does **not** answer a broader question:

> **"Does the overall pattern of behavior, across many transactions over time, still look normal and healthy?"**

Think of it like a credit card chip: the chip verification either works or it doesn't (that's the "lock"). But your bank's fraud department also watches for *patterns* — like your card being used in two countries within an hour — even when each swipe technically "worked." That pattern-watching is what QSENTINEL does, just for quantum signatures.

### 2.3 The Two Different Questions

| | Question | Who Answers It | How |
|---|---|---|---|
| **Question 1** | "Is this transaction valid according to the rules?" | The **Protocol itself** (QS-L) | Deterministic — yes/no, no guessing |
| **Question 2** | "Does this transaction's *behavior* still look statistically normal, alone and over time?" | **QSENTINEL** | Probabilistic — a statistical judgment call |

**Important honesty point:** A transaction can be 100% valid by the rules AND still get flagged by QSENTINEL as "statistically odd." That flag does **not** mean it's fake — it just means "a human should take a look." The two ideas (valid vs. normal-looking) are kept completely separate on purpose.

### 2.4 Why can't the existing lock do this by itself?

- A clever attacker could, in theory, forge a signature so cleanly that even the statistics look perfectly normal in a single instance — this is a mathematical limitation, not a bug we can code away.
- But that same attacker usually **can't** keep faking things perfectly across hundreds of sessions over time — small biases and drifts creep in. QSENTINEL's whole cross-session tracking exists to catch exactly that "slow leak" pattern (often called "low-and-slow" attacks).

---

## 3. The Big Idea: Two Separate Lanes

QSENTINEL's entire design rests on ONE simple rule: **never mix the "is it valid" decision with the "does it look suspicious" decision.**

```
 ┌─────────────────────────────┐        ┌──────────────────────────────────┐
 │   LANE 1: THE PROTOCOL       │        │   LANE 2: QSENTINEL (the watcher) │
 │   (the vault door)           │        │   (the security camera)           │
 │                               │        │                                    │
 │  - Deterministic (yes/no)    │        │  - Statistical (a judgment call)  │
 │  - Checks: timestamps,       │        │  - Checks: does the measurement   │
 │    tokens, correct order     │        │    pattern look "honest"?         │
 │  - Has the FINAL say on      │        │  - Produces an ADVISORY flag      │
 │    accept/reject             │        │    only — a note for a human      │
 │  - QSENTINEL can NEVER       │        │  - NEVER overrides Lane 1         │
 │    override this             │        │                                    │
 └─────────────────────────────┘        └──────────────────────────────────┘
```

Both lanes look at the same transaction, but they produce **two separate outputs** that are never mashed together into one confusing score. This separation is enforced not just "by being careful" — it's built into the code itself so it's structurally impossible to break (more on that in the tech stack section).

---

## 4. How It Actually Works — Step by Step

Here is the full journey of one transaction (called a "session") through QSENTINEL, explained like a factory assembly line:

**Step 0 — A session happens.** Someone sends a quantum-signed message. A full record of everything that happened (called a "transcript") is created and locked (frozen so nothing can quietly change it later).

**Step 1 — The Rulebook Check (FSM / Protocol Plane).**
A component checks basic bookkeeping rules:
- Is this a **replay** of an old, already-used signature? (freshness check)
- Does the sender actually have **permission** to do this? (authorization check)
- Did the steps happen in the **right order**? (sequencing check)

If any of these fail, it's an automatic, final REJECT — no statistics needed, no debate.

**Step 2 — Collecting the Evidence (Quantum Evidence Collector).**
The system looks at the measurement data (the classical information the quantum protocol already reveals — nothing extra or secret) and calculates a few numbers:
- **Mismatch rate (m)** — how often things didn't match up
- **Correlation (C)** — how related two sets of measurements are
- **Entropy (H)** — how "random" or "orderly" the outcomes look
- **Pauli-correction consistency** — a special quantum-only signal with no equivalent in ordinary (non-quantum) systems

Here's a subtle but important point: under completely honest, normal conditions, these first three numbers (m, C, H) are all really just different views of ONE underlying number. So instead of treating them as four separate clues, QSENTINEL checks whether they **agree with each other** the way honest behavior would predict. If they don't agree, that mismatch itself is the red flag — even if no single number looks alarming on its own. (This is like noticing a person's story doesn't quite add up, even though no individual sentence they said was an obvious lie.)

**Step 3 — Stage 1: "Does the honest model even apply here?"**
This step doesn't ask "is this an attack" yet. It first asks something more basic: "does this session's numbers even fit the pattern of *any* honestly-operating channel?" If the numbers are wildly inconsistent with any legitimate explanation, it's marked `MODEL_INVALID` and logged — this is a preliminary red flag, not a final verdict.

**Step 4 — Stage 2: "Given that it's a plausible honest session, is it actually an attack?"**
This is the core decision step. It combines two different statistical tests together (rather than checking them one-by-one and hoping for the best) and compares the result against a pre-calculated boundary. If it crosses that boundary, the session gets marked:
- `ACCEPT` — looks fine
- `FLAG (INVESTIGATE)` — worth a human look
- `FLAG (REJECT)` — strong statistical signal of an attack

**Important:** this is still just advisory. It never touches Lane 1's decision.

**Step 5 — Cross-Session Tracking (GLR-CUSUM) — the "slow leak detector."**
Every single session — flagged or not — feeds into a running tracker that watches for **slow drift over time**. This catches attackers clever enough to stay under the radar in any one session, but who can't hide a small, consistent bias forever across hundreds of sessions.

**Step 6 — Optional Detective Work (Attribution Engine).**
Only for sessions that already got flagged, this optional step tries to guess *which type* of attack it might be (for the human investigator's benefit). It never runs on clean sessions, so it costs nothing extra most of the time.

**Step 7 — Writing It All Down (Forensic Log).**
Every single session — no exceptions — gets a permanent, tamper-evident record written to a log. Each entry:
- is **digitally signed** so nobody can fake it after the fact,
- is **chained** to the previous entry (like a simple blockchain) so nobody can quietly delete or reorder history without it being detectable.

**Step 8 — The Alert.**
If something was flagged, a notification goes out to the security team (SOC). That's it — QSENTINEL's job ends at "tell a human." It never takes action on its own.

---

## 5. The Complete Tech Stack (What You Actually Need)

This is the full list of tools and technologies, explained in plain terms — what each one is, and **why** it was picked over other options.

| Layer | What's Used | What It's For, In Plain Words |
|---|---|---|
| **Programming Language** | **Python 3.11+** | The one language for everything — math, web server, and glue code. No need to juggle multiple languages. |
| **Quantum Simulation** | A **custom, hand-written simulator** (using NumPy), limited to 3 qubits | Since the real protocol never uses more than 3 quantum particles at once, there's no need for a huge, general-purpose quantum computing toolkit. A small ~150-line piece of code does the job faster and is easier for anyone to read and check. |
| **Statistics / Math Engine** | **NumPy + SciPy** (standard Python math libraries) | Used to run all the statistical tests (the likelihood calculations, the threshold comparisons, etc.) All formulas are written out explicitly so they can be checked by hand. |
| **Running Experiments at Scale** | Python's built-in **multiprocessing** (running many copies in parallel on one computer) | Testing needs thousands of simulated attack attempts. Since these don't depend on each other, they can just run side-by-side on your own computer's CPU cores — no need for cloud infrastructure or complex job queues. |
| **Backend / Server** | **FastAPI** + **Pydantic v2** | This is what turns QSENTINEL into something a website or app can talk to. It automatically generates documentation of its own API, which is handy for a live demo. |
| **Frontend / Dashboard** | **React** + **Vite** + **Recharts** | Builds the visual dashboard — the live "camera feed" people will actually watch during a demo. Shows charts, live session flow, and the drift graph. |
| **Database** | **SQLite** | A lightweight, file-based database — no separate database server needed to install or manage. Good enough because only one demo runs at a time. (There's a documented path to upgrade to a bigger database like PostgreSQL later if ever needed — but not required now.) |
| **Database Version Control** | **Alembic** | Keeps track of changes to the database structure over time, safely. |
| **Big Data Files (calibration results)** | Plain files: **JSON** (for readable settings/metadata) + **NumPy `.npz`** (for large number arrays) | Stores the results of big statistical calibration runs. Each file carries a security fingerprint (a hash) so you can always verify nothing was silently changed. |
| **Tamper-Proof Logging** | **SHA-256** hashing (chaining log entries together) | This is what makes the forensic log unforgeable — each entry "remembers" the previous one, so nobody can sneak in a change without it being detectable. |
| **Digital Signatures for the Log** | **Ed25519** (via Python's `cryptography` library) | A well-trusted, modern way to cryptographically "sign" each log entry so its authorship can't be faked. |
| **Dependency/Version Locking** | A single **lockfile** (`requirements.lock` or a Poetry lockfile) | Makes sure every teammate's computer runs the exact same versions of every tool — critical so results are reproducible and consistent. |
| **Testing** | **pytest**, split into 4 categories (basic correctness / integration / statistical validity / regression) | Confirms everything works correctly, stays correct over time, and — very importantly — confirms QSENTINEL truly never interferes with the protocol's own decisions. |
| **Code Boundary Enforcement** | **import-linter** | A tool that automatically fails the build if someone accidentally writes code that lets QSENTINEL "reach into" and influence the protocol's decision. This turns a rule ("don't let them mix!") into something the computer itself enforces, not just a promise. |

### 5.1 What is deliberately NOT used (and why that's actually a good thing)

This is just as important as what IS used. Keeping things simple and explainable is a strength, not a shortcut:

- ❌ **No AI/ML libraries** (no TensorFlow, PyTorch, scikit-learn) — QSENTINEL is 100% classical statistics, on purpose. This keeps it explainable and auditable.
- ❌ **No Qiskit / Cirq / PennyLane** (big quantum-computing SDKs) — overkill for a system that never uses more than 3 qubits.
- ❌ **No message brokers** (Celery, Redis, RabbitMQ) — this isn't a large distributed system; a single computer running things in parallel is enough.
- ❌ **No heavyweight database** (PostgreSQL, MongoDB) — not needed at this scale.
- ❌ **No Bayesian inference engines** (PyMC, Stan) — the math needed doesn't require this level of machinery.
- ❌ **No user login/authentication system** — out of scope for a demo/hackathon deliverable.

**Why this matters for your presentation:** every tool in the stack was chosen because it was *necessary*, not because it looked impressive. This is a strong selling point — it shows real engineering judgment.

---

## 6. What You Actually Need To Build This

### 6.1 Skills your team needs

| Skill | Why You Need It | Roughly How Much |
|---|---|---|
| **Python programming** (intermediate+) | Almost the entire system is Python | Essential — everyone touching the core system needs this |
| **Basic statistics** (hypothesis testing, likelihood, p-values) | Needed to understand/build Stage 1, Stage 2, and the drift detector | At least 1–2 people comfortable with this |
| **Basic quantum computing concepts** (qubits, entanglement, measurement) | Needed to build the small quantum simulator — but note, this is a *simplified*, fixed-size simulator, not deep quantum-computing engineering | 1 person can own this |
| **Web backend basics** (REST APIs) | For the FastAPI server | 1 person |
| **Frontend/React basics** | For the live dashboard | 1 person |
| **Cryptography basics** (hashing, digital signatures) | For the tamper-proof log — conceptually simple, implementation is short | Shared knowledge is enough |
| **Git / version control** | Standard for any team project | Everyone |

**Team size:** This is realistically buildable by a small team of **4–6 people** within a hackathon timeframe (a few days), *if* the scope stays disciplined and nobody tries to add extra features beyond what's specified.

### 6.2 Tools/software to install

- Python 3.11 or newer
- Node.js + npm (for the React/Vite frontend)
- Git
- A code editor (VS Code is a common, easy choice)
- pip or Poetry (for installing Python packages)
- SQLite (usually comes built-in with Python, nothing extra to install)

### 6.3 What you do NOT need

- No cloud servers or paid infrastructure
- No GPU (nothing here needs heavy computation power)
- No special quantum computer or quantum hardware access — everything is simulated
- No AI/ML training data or pretrained models

---

## 7. How the Project Is Organized (The Folder Structure, Simplified)

Think of the whole codebase as split into clearly separated "departments" that don't mix:

```
qsentinel-system/                (the main project folder)
│
├── qds/                         → THE PROTOCOL (the "vault door")
│      Handles the actual quantum signature process itself.
│      This part NEVER imports anything from the monitoring side.
│
├── qsentinel_monitor/           → THE WATCHER (QSENTINEL itself)
│      ├── protocol_evidence/    (the rulebook checks — FSM)
│      ├── quantum_evidence/     (Stage 1, Stage 2, drift tracker, evidence collector)
│      ├── orchestrator.py       (combines everything into one final advisory verdict)
│      └── forensic_log.py       (the tamper-proof logbook writer)
│
├── attacks/                     → TEST-ONLY simulated attacks, used to check
│                                   that QSENTINEL actually catches bad behavior.
│                                   Never used in the real running system.
│
├── experiments/                 → Where all the big test runs and statistical
│                                   calibration happen (offline, not during live use).
│
├── api/                         → The FastAPI web server that ties everything
│                                   together for the dashboard to talk to.
│
└── frontend/                    → The React dashboard people actually see.
```

**The one rule that's enforced by the computer itself, not just team discipline:** the `qds/` (protocol) folder is never, ever allowed to import anything from `qsentinel_monitor/` (the watcher). This is checked automatically every time code is submitted, so it can't be broken by accident.

---

## 8. Suggested Build Order (Roadmap)

Building everything at once is overwhelming — here's the sensible order, from foundation to polish:

1. **Build the core protocol** (`qds/`) — the actual quantum signature system, working correctly on its own first.
2. **Build the rulebook checker (FSM)** — the deterministic pass/fail checks.
3. **Build the evidence collector** — the code that extracts m, C, H, and Pauli-consistency from a session.
4. **Build the attack simulators** — fake attacks to test against (only after the "clean" pipeline above works).
5. **Build Stage 1** (the model-fit check).
6. **Build Stage 2** (the joint statistical decision) — this needs an offline calibration step first.
7. **Build GLR-CUSUM** (the cross-session drift tracker).
8. **Build the optional Attribution Engine.**
9. **Run the full test harness** — thousands of simulated sessions across all attack types, to see how well everything works.
10. **Build the API layer.**
11. **Build the frontend dashboard** — this can be the last piece, since the core system works and can be demoed without it if time runs short.
12. **Final validation and benchmarking** — confirm everything's numbers are trustworthy and well-documented.

**If you're short on time:** the frontend and the "extra comparison baseline" experiments are the safest things to trim — the core detection pipeline (steps 1–9) is what actually proves the idea works.

---

## 9. How To Present This (Suggested 5-Slide Story)

If this is for a hackathon/judged presentation (like Smart India Hackathon), here's a clean, logical story arc across 5 slides:

| Slide | What the Judge Sees | What They Learn | Why They'll Want the Next Slide |
|---|---|---|---|
| **1. The Idea** | A simple two-lane diagram: Protocol vs. Watcher | QSENTINEL is a separate, advisory-only layer — it never overrides the lock | "Okay, but what's actually happening inside that watcher lane?" |
| **2. How It Works** | The full pipeline diagram (rulebook check → evidence → Stage 1 → Stage 2 → drift tracker → log) | It's a real, specific mechanism — not a mysterious black box | "Can this actually be built in the time available, and can I trust the numbers?" |
| **3. Can We Trust It?** | A risk-vs-mitigation table, showing the two hardest problems solved structurally (not just promised) | The tech choices are minimal and deliberate; trust is built into the process itself | "Okay, feasible — but why should I care?" |
| **4. Why It Matters** | The value this adds, layered on top of the protocol's own security, PLUS an honest list of what it does *not* claim to do | The benefit and its honest limits, in the same breath | "What evidence backs all of this up?" |
| **5. What Backs This Up** | The design journey, including a documented "hostile review" process, and the research foundations | The design was pressure-tested, not just assumed correct | (Presentation closes — no open questions left hanging) |

**Golden rule for the deck:** never make a claim on one slide that isn't either proven on the next slide, or honestly labeled as "not yet measured." Judges trust teams that are upfront about what's still unproven far more than teams that oversell.

---

## 10. Being Completely Honest: What QSENTINEL Does NOT Do

This section matters a lot for credibility — both in front of judges and in real security work. Overclaiming is the fastest way to lose trust.

- It **cannot catch a perfect, statistically flawless single fake signature** — if an attacker somehow makes a forgery whose statistics look *exactly* like a real one, no statistical system (this one included) can catch it in a single session. This is a fundamental mathematical limit, not a flaw in the design.
- It **does not add extra cryptographic security** to the underlying protocol — the protocol's own security proof stands on its own; QSENTINEL just watches it.
- It **has not been tested against a smart attacker who knows exactly where QSENTINEL's detection thresholds are set** — that's a known, named open question.
- Its protection against impersonation and unauthorized access **depends on the trustworthiness of the system that issues tokens/credentials in the first place** — if that outside system is compromised, QSENTINEL can't fix that.
- **No performance numbers (like "95% detection rate") should be quoted yet** — every number that exists from earlier testing was measured under an older version of the design and needs to be re-measured before it can be trusted or presented as current.
- It doesn't handle protecting the physical hardware or communication channels outside the software itself — that's a separate, future concern.

**Why include this in a presentation?** Being upfront about limitations, paired with a clear plan for how each one will be validated, reads as *more* credible to technical judges — not less. It shows the team actually understands their own system deeply.

---

## 11. Quick Cheat-Sheet Summary

**What it is:** A non-AI, statistics-only "security camera" for a quantum digital signature system.

**What it never does:** Block, delay, or override a valid signature.

**Core mechanism (memorize this order):**
`Rulebook check → Collect evidence (4 numbers) → Stage 1 (does it fit an honest pattern?) → Stage 2 (is it an attack?) → Cross-session drift tracker → Tamper-proof log → Alert a human`

**Core tech stack (memorize this list):**
`Python + NumPy/SciPy (statistics) + a small custom quantum simulator + FastAPI (backend) + React (frontend) + SQLite (storage) + SHA-256 & Ed25519 (tamper-proof logging)`

**What makes it trustworthy:**
1. The "don't interfere with the lock" rule is enforced by the code itself, not just team promises.
2. Statistical thresholds are calculated once, offline, and never quietly recalculated during live use.
3. Every session — flagged or not — gets logged permanently and can't be secretly edited later.
4. The team is upfront about exactly what still needs to be tested and what mathematically can never be caught.

**One-line pitch for judges:**
> "QSENTINEL doesn't try to be a smarter lock — it's the tireless analyst watching the lock, using honest statistics instead of an AI black box, that catches the slow, patient attacks a single security check would miss."

---

*This guide was built by simplifying the full technical design review, architecture freeze document, and implementation blueprint into plain language. For exact formulas, API details, database schemas, and the complete limitations table, refer back to the original technical documents — they are intentionally kept out of this simplified guide but are available for the Q&A/backup section of any technical presentation.*
