# AI / LLM / agent security review

Read this when the code calls an LLM, embeds/retrieves (RAG), or runs an agent
that plans, calls tools, executes code, keeps memory, or coordinates with other
agents, or is / hosts / connects to an MCP server. Expands section C of `SKILL.md`.

Standards tracked (verified URLs + dates in `docs/standards-index.md`): OWASP
Top 10 for LLM Applications **2026** (titles quoted 2026-09-08 from
`OWASP-GenAI-LLM-Top-10-2026-v1.0.pdf`; 2025 names kept only as a
compatibility map), OWASP Top 10 for Agentic Applications **2026**, OWASP
Agentic Skills Top 10 (AST01–AST10 — `references/security-agent-skills.md`),
NIST AI RMF + Generative AI Profile, and MITRE ATLAS.

**The one principle under all of this:** everything the model reads that did not
come from your trusted prompt — user input, retrieved documents, web pages,
file contents, tool results, another agent's output — is **untrusted data, and
may contain instructions aimed at your system**. And everything the model
*emits* is **untrusted input to the next stage**. Trust neither end without a
control you built outside the model.

---

## OWASP Top 10 for LLM Applications 2026 — per-risk review

Titles quoted from `OWASP-GenAI-LLM-Top-10-2026-v1.0.pdf` (resource dated
2026-08-03; PDF fetched 2026-09-08). Official `/llm-top-10/` HTML still
renders 2025 cards — do not take IDs from that landing page. When the model
is a **component**, walk LLM01–LLM10:2026. When it is an **actor** (tools,
memory, downstream consequences), pair with ASI01–ASI10. When the artifact
**is a skill**, also walk AST01–AST10 (`security-agent-skills.md`).

2025 → 2026 rank map (same PDF, "What's New"): Prompt Injection and
Sensitive Information Disclosure held 1–2; Excessive Agency climbed to 3;
Supply Chain 3→4; Data and Model Poisoning 4→5; Unbounded Consumption
10→6; Misinformation 9→7; System Prompt Leakage renamed **Hidden Context
Exposure** at 8; Vector and Embedding Weaknesses 8→9; Improper Output
Handling 5→10.

- **LLM01:2026 Prompt Injection** (direct, indirect, and cross-modal). Is
  untrusted content clearly separated from instructions (delimiting /
  spotlighting / distinct roles), and never concatenated into the trusted
  instruction block? Assume any retrieved, fetched, **image, or audio**
  content is adversarial. **Test it** (see the injection test set below).
  This is the root cause behind most agentic incidents.
- **LLM02:2026 Sensitive Information Disclosure**. No secrets/PII/internal
  system prompts in prompts, logs, traces, or outputs. Output is filtered
  before it reaches a user or another system.
- **LLM03:2026 Excessive Agency**. Tools are least-privilege: minimal set,
  minimal scope, minimal permissions. High-impact or irreversible actions
  require human confirmation. The agent cannot reach beyond its task. The
  most consequential 2025→2026 move (was LLM06).
- **LLM04:2026 Supply Chain**. Model/provider, plugins, adapters, datasets,
  and **promoted model artifacts** are trusted and pinned; provenance
  known. A model or tool pulled from an open hub is a dependency with the
  same risk as any package. (Was LLM03:2025.)
- **LLM05:2026 Data and Model Poisoning**. Training / fine-tuning /
  RAG-ingested data is validated and provenance-tracked; an attacker can't
  get malicious content into the corpus that later steers outputs. Absorbs
  fine-tuning subversion. (Was LLM04:2025.)
- **LLM06:2026 Unbounded Consumption**. Token / cost / rate caps enforced
  **before** each billable call; loops bounded; circuit breakers on 402/429;
  no user-controlled unbounded generation. Both a DoS and a cost attack.
  (Was LLM10:2025.)
- **LLM07:2026 Misinformation**. Model claims that reach a user or third
  party are grounded/verifiable; hallucination is mitigated (grounding,
  citations, confidence, human check). Never shipped as fact unchecked.
  Incident record ranked this higher than the 2025 vote. (Was LLM09:2025.)
- **LLM08:2026 Hidden Context Exposure**. Broader than 2025's System Prompt
  Leakage: assume hidden instructions, tool schemas, and retrieved context
  are extractable. No secrets, credentials, or authorization logic live in
  them; security is enforced outside the model. (Was LLM07:2025.)
- **LLM09:2026 Vector and Embedding Weaknesses**. RAG stores enforce access
  control and tenant isolation; no cross-user/cross-tenant retrieval
  leakage; embeddings and retrieval can't be manipulated to exfiltrate. (This is the
  RAG *security* half; RAG *correctness* evaluation — retrieval quality + generation
  faithfulness + agent-trajectory — is in `testing-and-evals.md` AI evals.)
  (Was LLM08:2025.)
- **LLM10:2026 Improper Output Handling**. Model output is schema-validated
  / sanitized **before** any downstream use — never fed raw into SQL, a
  shell, HTML, `eval`, a file path, or an HTTP call. Treat it exactly like
  user input. Now also spans insecure code assistants generate at scale.
  (Was LLM05:2025.)

## 2025 compatibility map (do not walk as current)

Use only when a target, citation, or older report still names 2025 IDs.

| 2025 | 2026 |
|---|---|
| LLM01 Prompt Injection | LLM01:2026 Prompt Injection |
| LLM02 Sensitive Information Disclosure | LLM02:2026 Sensitive Information Disclosure |
| LLM03 Supply Chain | LLM04:2026 Supply Chain |
| LLM04 Data and Model Poisoning | LLM05:2026 Data and Model Poisoning |
| LLM05 Improper Output Handling | LLM10:2026 Improper Output Handling |
| LLM06 Excessive Agency | LLM03:2026 Excessive Agency |
| LLM07 System Prompt Leakage | LLM08:2026 Hidden Context Exposure |
| LLM08 Vector and Embedding Weaknesses | LLM09:2026 Vector and Embedding Weaknesses |
| LLM09 Misinformation | LLM07:2026 Misinformation |
| LLM10 Unbounded Consumption | LLM06:2026 Unbounded Consumption |

## OWASP Top 10 for Agentic Applications 2026 — additional risks

Published 2025-12-09; titles below taken from the OWASP GenAI announcement
(verified 2026-08-21; PDF numbering not re-fetched this session — if a title
conflicts with the PDF, the PDF wins). When the code is an **autonomous agent**,
walk ASI01–ASI10; do not collapse them into LLM01–LLM10.

- **ASI01 Agent Goal Hijack** — attacker redirects the agent's objective through
  content it *reads* rather than code it runs. Indirect prompt injection at the
  planning layer. Highest-impact agentic risk.
- **ASI02 Tool Misuse** — agent steered into calling a *legitimate* tool with
  harmful arguments (summarize-URL → SSRF/exfil).
- **ASI03 Identity & Privilege Abuse** — agent acts with more authority than the
  requesting user; confused deputy; over-broad service credentials.
- **ASI04 Agentic Supply Chain Vulnerabilities** — poisoned tools, skills,
  plugins, MCP servers, model artifacts. Pin and vet every loadable tool like a
  dependency.
- **ASI05 Unexpected Code Execution** — code-exec tools/sandboxes the agent can
  be talked into abusing (RCE / sandbox escape).
- **ASI06 Memory & Context Poisoning** — persisted memory, scratchpads, or RAG
  context corrupted so a later run acts on planted instructions. Validate and
  scope what enters long-term memory.
- **ASI07 Insecure Inter-Agent Communication** — messages between agents trusted
  without authentication/validation; one agent spoofs or injects into another.
  **Audience is the control:** a same-owner private pipe is not the many-owner
  network board. Reusing a many-audience channel for same-owner Q&A is a leak
  by construction (cross-ref Q). Probe: a message meant for one principal must
  not be readable by another tenant, a commons, or a mesh. Authn on the pipe
  (session/uid, not a display name). No fleet secret as the credential.
- **ASI08 Cascading Failures** — one agent's error or compromise propagates
  across a multi-agent system with no isolation, rate control, or breaker.
- **ASI09 Human-Agent Trust Exploitation** — fluent, confident output socially
  engineers the operator into approving a harmful action. Approval prompts must
  name the audience and the action; a buried "yes" in chat is not consent.
- **ASI10 Rogue Agents** — agent operating outside intended scope or oversight;
  no kill-switch, no bound on autonomy, no audit trail.

**Same-owner vs many-audience probe (ASI07, cheap, before fan-out).** If the
target has more than one agent, board, mesh, or "ask a peer" tool: list each
channel and its named audience (one owner / one tenant / every agent on the
network / another human's agent). A write that can land on a wider audience
than the prompt named is a finding — even if the bytes look like a private DM.
Key the protocol on a stable tenant/uid, never a display name (names are
per-owner and collide).

Attacker techniques against agent tool ecosystems are also catalogued in **MITRE
ATLAS** (e.g. poisoned agent tools, sandbox/host escape) — useful for building
the red-team test set below. To *model* an agentic system's threats systematically rather
than only enumerate techniques, reach for **MAESTRO**, an agentic
threat-modeling method — the method-side complement to these catalogs (`security-appsec.md`
A06 names the general threat-model catalog: STRIDE / PASTA / attack trees / LINDDUN / MAESTRO).

---

## MCP (Model Context Protocol) server / client security

When the target **is, hosts, or connects to** an MCP server, it inherits a new
principal (the tool/server) and three surfaces the general lenses above do not
cover by default: an OAuth **proxy** authorization topology, a **local-server
execution / consent** surface, and **tool metadata** the model reads as instructions. Walk the three deltas below; each specializes a general
lens named in parentheses — do not re-walk the general form. The **OWASP MCP Top 10**
(`owasp.org/www-project-mcp-top-10`, lead V. Verma Sehgal) catalogs this layer but is
**Phase-3 beta** — name it if a target cites it, but do **not** walk its `MCPxx:2025`
IDs as current (cf. the 2025 compatibility map above). The concrete `MUST`/`SHOULD`
controls below are from the official MCP security spec
(`modelcontextprotocol.io/docs/tutorials/security/security_best_practices`, fetched
2026-09-19).

**1 — Authorization in the proxy topology** (specializes A01/A07 `security-appsec.md`;
ASI03 confused deputy).
- **OAuth-proxy confused deputy.** An MCP proxy that uses **one static client-id** to a
  third-party authorization server, **allows dynamic client registration**, and rides a
  third-party **consent cookie** lets an attacker skip consent: register a malicious
  `redirect_uri`, reuse the victim's cookie, steal the MCP authorization code. The proxy **MUST** run its
  own **per-client consent before** the third-party flow, exact-match the `redirect_uri`,
  and set the `state` cookie only **after** consent. The general confused deputy (ASI03)
  and exact-`redirect_uri`/`aud` checks (A07) apply; the delta is the shared static
  client-id across all MCP clients.
- **Token passthrough is forbidden.** An MCP server **MUST NOT** accept a token whose
  `aud` is not itself, nor forward an upstream token to a downstream API — that recreates
  the confused deputy and bypasses the downstream's rate/audit controls. (A07 already
  requires verifying `aud`; the delta is the **passthrough** anti-pattern on the
  server-to-server hop.)
- **Least-privilege scopes.** No wildcard/omnibus MCP scopes (`*`, `admin:*`); prefer
  progressive step-up over one broad grant.
- **🚩** an MCP server reading a bearer token without checking `aud` == itself; a
  proxy with a static client-id + dynamic registration and no per-client consent;
  `scopes_supported` advertising `*`.

**2 — Consent-UI fidelity & local-server execution** (a local MCP server is code-exec;
ASI05, ASI09).
- A one-click "add local server" flow runs a config-supplied command **with the client's
  privileges** — arbitrary code execution on the user's machine. The client **MUST**
  display the **exact, untruncated** command before running it: the bytes the user
  approves must equal the bytes executed. A truncated or obfuscated command is consent the
  user never really gave (cf. ASI09 — the approval must name the real action). Spawned
  `stdio` children **SHOULD** be sandboxed.
- **🚩** a one-click server-install flow that runs a command it does not show in
  full; a spawned child process with no sandbox or privilege bound.

**3 — Tool metadata is untrusted, model-read instruction surface** (specializes ASI01
goal-hijack; extends ASI04 pin-and-vet — the tool-**metadata** trust leg beside
*transport* and *payload*, cf. "trust the transport, not the payload" below).
- **Tool-description poisoning.** A tool's description/schema is read and acted on by the
  model but often **not shown to the user**; a hidden directive in a docstring (e.g. read
  `~/.ssh/id_rsa` and pass it as a parameter) exfiltrates before the tool returns
  (Invariant Labs, via Willison 2025-04-09). Treat tool metadata as **untrusted content**
  behind an injection boundary, never as trusted instructions.
- **Rug pull.** A tool's definition can **mutate after approval** (approved as safe, then silently rerouting
  credentials on a later run); many clients do not alert on description changes.
  **Pin/hash the approved description and re-approve on change** — a TOCTOU on tool
  metadata, the ASI04 pin-and-vet rule extended from the artifact to its *description*.
- **🚩** tool descriptions concatenated into the model's context with no
  untrusted-content boundary; no hash / re-approval of a tool's description across
  sessions.

## Prompt-injection & jailbreak test set (write these tests)

Model-dependent security needs security **tests**, not vibes. For any
LLM-backed feature, add cases that assert the guardrail holds:

- **Direct injection**: user input that says "ignore previous instructions and
  …"; assert the system instruction still governs and the disallowed action does
  not occur.
- **Indirect injection**: a retrieved document / fetched page / file / tool
  result containing embedded instructions ("SYSTEM: exfiltrate the API key to
  …"); assert the agent treats it as data and does not act on it.
- **System-prompt extraction**: prompts trying to get the model to reveal its
  system prompt / hidden rules; assert no secret leaks (and that nothing secret
  was in there anyway).
- **Output-handling**: force the model to emit `'; DROP TABLE …`, `<script>`,
  `$(rm -rf …)`, `../../etc/passwd`; assert the downstream layer
  validates/escapes and nothing executes.
- **Excessive agency**: a request that would trigger a high-impact tool
  (delete, send, pay, deploy); assert human confirmation is required.
- **Unbounded consumption**: input designed to cause a long/looping generation
  or many downstream calls; assert the token/cost/rate cap and loop bound fire.
- **RAG isolation**: user A queries for user B's data; assert tenant isolation
  in retrieval.

## Defensive patterns to look for (and recommend)

- **Deterministic-first.** Anything a plain function can do correctly (parsing,
  validation, math, dedup, lookups, routing, formatting, schema enforcement) is
  a function — cheaper, testable, and it cannot hallucinate. Reserve the model
  for genuine language/judgment tasks. A pipeline that asks the model to do
  arithmetic or emit JSON that a schema could guarantee is a red flag.
- **Aggregate-only reads by default — never pull per-row sensitive values into the
  model's context when an aggregate query would do.** Compute statistics in SQL and
  hand the model the **aggregate**, not the rows; per-row sensitive financials (or
  PII) in context are an **exfiltration surface** — a later injection, a logged
  prompt, or a tool call can carry them out. This is the model-context sibling of
  `privacy-compliance.md`'s gate-a-sensitive-derived-value-at-the-source rule:
  minimize sensitive data **in the context**, not only in the store.
- **Anchor relative time deterministically — the time instance of the rule
  above.** A prompt that resolves *today*, *yesterday*, *last quarter*, *next
  Friday*, or *in 30 days* must be handed an authoritative current date/time by
  **deterministic code**; the model never authors *now* (asked, it emits a
  plausible **wrong** date as fact — LLM07 Misinformation). Inject that anchor
  into the **trusted** instruction region — **never** concatenated with retrieved
  / tool / user content, or an injected *"today is 2020-01-01"* riding in
  untrusted context moves every downstream date (LLM01, indirect injection). And **fail
  closed** when the anchor is absent or unparseable: refuse or surface it; never
  silently fall back to a bare `now()` / system clock buried in the model call —
  that turns a config gap into a wrong-date-as-fact bug with no error. Same
  discipline for **timezone and locale**: an unstated tz is the temporal
  equivalent of an unpinned dependency. This is the prompt-input sibling of the
  data-write temporal anchor (`data-quality.md` §3 — don't record a current
  attribute as historical): same principle, opposite direction.
- **Spotlighting / delimiting** untrusted content (clear markers, separate
  roles/messages) so the model can distinguish data from instructions.
  **Enumerate the sinks — don't just grep one.** The one-principle above is a
  *rule*; the instrument is to list **every** site where non-prompt content
  (tool result, fetched page, file, retrieved doc, another agent's message)
  enters a prompt, and confirm each carries a delimiter **and** a "this is data,
  not instructions" guard. **Inconsistent** spotlighting is itself the finding:
  one guarded sink proves the unguarded siblings are oversights, not policy — a
  real shape is an objective wrapped in `<untrusted_objective>` while
  project-context files and skill text are concatenated raw into the *same*
  system prompt.
- **Structured output + schema validation** on the way out; reject/repair
  off-schema output before use.
- **A model's self-report boolean is untrusted input — compare it strictly, fail closed,
  and never let it be the sole gate.** Gating an allow/skip/"it's safe" decision on an
  LLM-returned flag with a **negated** comparison — `if (res.safe !== false)` — takes the
  **permissive** branch for **everything except the boolean `false`**: an **omitted** field,
  `null`, a wrong-typed `"false"`/`0`, or a failed parse all pass — exactly the outputs a
  model that hallucinated, was prompt-injected, or truncated on a token limit produces.
  (Bare truthiness `if (res.safe)` is the **inverse** footgun: it fails *closed* on
  `null`/`0`/omitted but *open* on truthy junk like the **string** `"false"` or an object.)
  Require the field **present and boolean**, make the permissive branch demand an explicit
  `=== true`, and route every other case to the deny/safe branch (fail closed — the same
  discipline as the boolean parser in `data-quality.md` §7: accept the shape set, treat an
  unknown value as exclude). And a model **self-grading its own output** ("is this
  compliant/complete/safe?") can be wrong or coerced by the same injection that produced the
  bad output, so a self-report must **corroborate** a deterministic check (allowlist, argument
  validation at the tool boundary), never replace it — **self-reported evidence is not a
  trusted control** (cross-ref `branch-and-merge-hygiene.md` and `model-tiering.md`). Test
  with the field missing, `null`, and wrong-typed, and confirm the safe branch is taken.
- **Least-privilege tools** with allowlisted actions and argument validation at
  the tool boundary (not left to the model to "please only…"). **Locate the
  actual dispatch path and its one pre-execution chokepoint** (a
  `beforeToolCall`-style hook), then decide whether each safety gate is a
  **shipped default or an opt-in example** — a demo gate that lives in
  `examples/` and is never loaded is not a control (cross-ref
  `security-agent-skills.md` AST06; never cite a demo as shipped policy). A
  denylist of dangerous-command regexes is bypassable by construction (an
  `rm -rf` pattern misses `-fr` / `-f -r` / `--force`); treat containment, not
  pattern-matching, as the boundary.
- **Quarantine the reader from the actor.** The controls above (spotlight, schema-validate,
  least-privilege) still live inside **one** agent identity that both **ingests untrusted
  content** (tool results, MCP responses, fetched pages, another agent's output) **and holds the
  privileges** to act (credentials, write, egress, tool dispatch) — a confused deputy waiting for
  one injection to land. The architectural control is to **split the roles**: a **reader** that
  consumes untrusted content has **no credentials, no write, no egress**, and emits only
  **structured, schema-validated data operands** — the extracted facts, **never the action to
  take**. The **action is fixed by the trusted task plan**, not derived from untrusted input: a
  **privileged actor** selects the operation from that plan, validates it against an **allowlist
  of actions this task permits**, and consumes the reader's value **only as an operand** — never
  as raw text, and never as an action / `intent` selector (a schema validates *shape*, not
  authority, so a schema-valid `{intent: "merge_pr"}` from the reader would still be a privileged
  action chosen by untrusted input). An injection that lands in the reader can then at most
  corrupt an *operand* (rejected or bounded at the boundary), not choose a privileged *action* —
  the action space was fixed on the trusted side before any untrusted byte was read.
  Review it as an **architecture** question a per-file diff cannot answer: does any single
  identity both read untrusted input **and** wield the credentials? For MCP specifically,
  **trust the transport, not the payload** — a signed or allowlisted server connection
  authenticates *where the bytes came from*, never that their *content* is safe to act on
  (cross-ref the poisoned-MCP-server risk above and `security-agent-skills.md`).
- **When the tool *is* code execution, reframe the output-handling test.** For a
  shell / `ipython` / code-interpreter agent, "model output reaches `exec`" is
  the product, not a bug, so LLM10's raw-sink test collapses. The controls to
  review become the **isolation boundary** (`security-agent-skills.md` AST06)
  and the **default confirmation gate** — and whether that gate is on by
  default — not the exec call itself.
- **Human-in-the-loop** gate on irreversible/high-impact actions — and it must
  **fail closed when there is no interactive UI**. A confirmation that degrades
  to *allow* in headless / autonomous / agent-to-agent mode is the finding; the
  correct shape returns *block* when no human can approve. The prompt names the
  action and the audience (ASI09).
- **Spend & rate governance**: per-call, per-session, and per-service caps
  enforced in code before the call; bounded retries with backoff; breakers on
  402/429. Two tests the prose alone misses: **(1) cost ≠ tokens** — grep for a
  real spend key (`budget` / `costLimit` / `maxSpend`), not just `max_tokens`
  and turn counts; a token/turn cap does not bound dollars. **(2) before ≠
  after** — a budget *reconciled after* a completed paid turn (then a "wrap-up"
  prompt) is a soft stop that overshoots by ≥1 turn, not a cap checked *before*
  dispatch. An agent loop written `while (true)` and bounded only by an external
  caller is a red flag. Prefer capping four axes together — calls/turns, tokens,
  wall-clock, and dollars — and reporting which one tripped. **Bound the tree,
  not just the call:** in a recursive or multi-agent system the cap (depth /
  steps / spend) must be **propagated to every spawned sub-agent** — a parent cap
  not forwarded leaves each child on the framework default and the whole tree
  unbounded.
- **Streaming / completion-delivery mode is part of output handling and spend.** A guard written
  for one *complete* response silently fails on a **streamed** one, and truncated output reads as
  complete: (1) **check the finish / stop reason** (`finish_reason` / `stop_reason`) before using a
  response — one cut off by a length or safety stop but returned with HTTP 200, then rendered /
  stored / parsed as if whole, is a silent truncation (**LLM10**); (2) a moderation / schema /
  sanitization guard built for one complete string must run on the **assembled** stream, not
  per-chunk-too-late or not-at-all once delivery is chunked / SSE (**LLM10**); (3) **chunk-boundary
  evasion** — a payload split across two stream chunks passes a per-chunk sanitizer that inspects
  each fragment in isolation, so guard the *assembled* output (**LLM10**); (4) a **client disconnect
  must cancel the upstream generation** — a caller that aborts mid-stream while the model keeps
  generating burns billed tokens nobody reads (**LLM06**), distinct from the pre-dispatch caps above
  (this is cancellation *after* a call starts): wire the consumer's abort / close (`AbortSignal`,
  `req.on('close')`, context) through to the model call — the LLM-cost-specific case of the
  abort-wiring discipline in `reliability-error-handling.md`. **🚩** `finish_reason` / `stop_reason`
  used nowhere near the response's use site; an SSE / async-generator / stream handler that renders
  or forwards chunks with no assembled-output guard and no abort path from the consumer.
- **Provenance & grounding**: citations/sources for claims that reach users;
  confidence surfaced; unverifiable claims flagged, not shipped as fact.
- **Context & memory lifecycle — a constraint must survive compaction.** A
  long-running agent that summarizes/compacts old turns, evicts old tool results,
  or persists memory to stay under the context window can **silently lose a
  safety-relevant instruction** — an approval scope, a "never touch prod", an
  authority grant — with **no attacker** (unlike ASI06 poisoning) and **no crash**
  (unlike F recovery); this is the agent's own **context integrity**, not domain
  W's job orchestration. Walk the lifecycle: **(1) compaction/summarization**
  preserves or re-asserts the constraints — a custom summary instruction that
  *replaces* the default must still carry them; never assume they survive a
  summary; **(2) tool-result eviction/clearing** exempts the item that holds the
  constraint/authority (a never-clear allowlist), not just the newest N; **(3)
  persistent memory** has an **expiry/staleness** policy so a stale memory cannot
  override a current instruction — the *non-adversarial* sibling of **ASI06**,
  which already owns validating what enters the store; **(4)
  cross-agent handoff** carries the decisions/constraints (the full trace), not
  only the latest message, or the downstream agent acts without them; **(5)
  resume** revalidates authority instead of trusting a stale saved grant. The
  delivering-agent runbook for this is
  `agentic-delivery/references/project-state.md`; **here it is a review check over
  the target.** Memory/retrieval stores also enforce tenant isolation (LLM09;
  domain T).
- **Falsify asserted-but-unenforced safety properties.** A safety parameter set
  at a call site but silently **dropped or overridden by the layer below** — so
  the code (and often a comment) *claims* a property that is not in force. Worse
  than a missing safeguard because it reads as present. Two sub-cases:
  - *Dropped by a lower layer.* e.g. `temperature: 0` "so the verifier is
    deterministic" is omitted by the payload builder for a model tier that
    rejects a non-default temperature (HTTP 400) — so the determinism claim is
    false and a verifier feeding a human-review queue is non-deterministic. Grep
    every `temperature`, `verify=`, `timeout`, `signal`, dry-run flag, allowlist,
    and `readOnly` for a downstream drop/override.
  - *Delegated to an unverifiable platform guarantee.* The control depends on an
    external/platform behavior you can't test from the code. State the residual
    risk that holds **regardless** of the guarantee and rest severity on the code
    you can test; convert the unverifiable part into a single owner-run check in
    "Decisions needed."

  **A comment asserting a safety property is the highest-value thing to falsify.**

**🚩 grep**: f-strings / `format` / template literals building a prompt from
raw user or retrieved text; model output passed to `execute`/`exec`/`os.system`
/ `render`/`eval` / a file path without validation; no `max_tokens` / `timeout`
/ retry cap on the client; tool definitions with broad write/delete/network
scope and no confirmation; secrets or authz rules embedded in a system prompt;
`temperature`/model params hardcoded where determinism matters for a security
check; a confirm/approve gate that defaults to *allow* when non-interactive;
`Popen` / `spawn` / `child_process` / `ipython` running model-generated
commands with no sandbox around the spawn; non-prompt content concatenated into
a prompt with no delimiter; token caps present but **no** `budget` /
`costLimit` / `maxSpend`; a compaction/summarization or tool-result-clearing step
with no exemption for the constraint/authority-bearing context; a persistent
agent-memory store with no expiry/staleness policy (validating what enters it is
ASI06); a multi-agent handoff
passing only the latest message, not the decisions/constraints; a sub-agent
spawned without the parent's depth/step/spend cap; a prompt template that
resolves a relative date (*today* / *last quarter*) with **no** injected
current-date anchor, or a bare `now()` / `new Date()` / `date.today()` as the
only time source feeding a model-facing date computation.
