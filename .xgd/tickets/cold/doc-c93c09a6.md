---
uid: doc-c93c09a6
id: DOC-9
type: doc
title: Web Reference Fetching and the Design Brief
created_by: xgd
created_at: '2026-06-30T01:02:03.091774+00:00'
updated_at: '2026-06-30T01:02:03.091774+00:00'
completed_at: null
last_field_updated: created_at
status: null
fields:
  doc_kind: architecture
---

# Web Reference Fetching and the Design Brief

## 1. Purpose & Scope

The 1st contact builder needs to ingest external websites — for inspiration, comparison, and direct conversion — and use them as load-bearing context for AI-driven site design. This document captures the architectural model for that capability and the canonical site-level memory artifact it feeds into: the **Design Brief**.

Paired with:

- [[DOC-4]] — product vision
- [[DOC-5]] — platform architecture
- [[DOC-7]] — framework architecture principles
- [[DOC-8]] — builder UI architecture principles

**This document commits to:**

- A two-level extraction model: the **Reference Digest** (always) and **Site Transcription** (when conversion is requested).
- A single shared artifact — the Reference Digest — that serves both the user's view and the AI's view of any external site.
- A per-site **Design Brief**: a long-lived sectioned-markdown document that holds the canonical site memory (decisions, references, voice, palette, etc.).
- A two-tier memory model: chat-scoped (digests, screenshots, transcripts) vs. site-scoped (the Brief).
- Cloudflare-native infrastructure: Workers + `fetch` for static pages, Cloudflare Browser Rendering for JS-rendered pages, R2 for heavy assets, KV for caching.
- A digest report as the primary display surface in the builder's right panel; iframe display is a secondary fallback.
- A KMS-aware document shape from day one (summary + table of contents + sectioned body), so future knowledge-management retrofits are free.
- Pre-launch readiness for the "paste URL → editable themed site" killer demo.

**This document deliberately does not commit to:**

- Exact AI tool call schemas (defined in REQ tickets per iteration).
- The specific knowledge-management system or search-provider implementation.
- A "references library" / cross-chat boards UI.
- A click-to-edit affordance on imported sites in the preview.
- Specific cost ceilings or per-customer rate-limit numbers (carried as open questions).

---

## 2. Use Cases

### 2.1 Convert existing site (killer demo, pre-launch)

The operator pastes a URL of an existing website. The system fetches and analyzes it, then reproduces it inside the 1st contact framework — same palette, type, layout intent, content — as an editable draft. The operator then talks to the AI to refine it in real time.

This is a pre-launch must-have. It is the most visceral demonstration of the platform's value and is the highest-bar use case for extraction fidelity.

### 2.2 Inspiration onboarding

The operator describes a business ("local plumber"). The system runs a web search, fetches the top 3–5 candidates, produces a Reference Digest for each, and presents them as a comparative report in the right panel. The AI leads a structured discussion ("here's what I like about A versus B — emergency callout focus, family-business trust, flat-rate pricing — which positioning fits you?"), and decisions crystallize into the Design Brief.

### 2.3 Asset links

The operator pastes URLs to specific assets (images, logos, sometimes a PDF or document). The system downloads them to R2 and registers them as project assets. Lighter weight; no digest required.

---

## 3. Core Concept — The Reference Digest

A **Reference Digest** is the structured representation of an external website. It is produced by the extraction pipeline and used as **the same artifact for both the user and the AI**.

### 3.1 Why convergence matters

If the AI looks at raw HTML and the user looks at an iframe, the two are talking about different things and any agreement is incidental. When both look at the same digest:

- The AI's reasoning is grounded in an artifact the user can verify line-by-line.
- "I like the centered hero on site B" points at a specific entry in a specific section.
- The conversation becomes auditable, not performative.

This convergence is itself a trust property worth designing for.

### 3.2 Shape (logical)

A digest is a markdown document plus R2-stored assets. Logical contents:

- **Summary** — 1–2 paragraphs, AI-generated, distilling positioning and overall impression.
- **Screenshot strip** — mobile / tablet / desktop renders stored in R2, referenced by markdown image syntax.
- **Palette** — dominant colors with role inference (background, body text, accent, CTA), not just top-N.
- **Typography** — body family/size, heading family/size, weights and scale actually used.
- **Layout signals** — centered vs left, content max-width, vertical rhythm, density.
- **Imagery style** — photography vs illustration, treatments (rounded, shadows, none).
- **Content tree** — heading hierarchy, sections, lists, forms, nav, repeated structures.
- **Asset inventory** — images with classifications (hero, product, headshot, testimonial), each with R2 keys.
- **AI commentary** — what the AI observed and would recommend keeping or breaking from.

The digest is itself a markdown document with explicit `##` section boundaries — see §9 for why this matters.

### 3.3 Lifetime

Digests live in the chat history that produced them. The chat is persistent and searchable across sessions (planned infrastructure). A digest from one chat is reachable from a later chat via search. The operator does not lose ground when they return — but the canonical memory is the Design Brief, not the digest soup.

---

## 4. Core Concept — The Design Brief

A **Design Brief** is the per-site canonical memory document. One Brief per site. Markdown, sectioned, KMS-aware shape (§9), lives as a first-class site artifact.

### 4.1 What it holds

- A short "project context" narrative — who the customer is, what the site is for.
- The crystallized **decisions**: palette, typography, layout principles, navigation, voice & tone, content priorities. Each starts as `TBD` and is filled in as the conversation crystallizes.
- A **references** section listing reference digests the operator and AI worked with, each with a brief summary and the AI's commentary on what was kept or rejected.
- **Open questions** — things the AI flagged that the operator hasn't yet answered.

The Brief is **distilled, not a transcript**. It holds what was decided, not what was discussed. Discussion is in the chat history, which is durable and searchable; the Brief is the canonical answer.

### 4.2 Update discipline

The AI proposes Brief edits when a decision crystallizes ("Want me to add this to the Brief?"); the operator confirms with one action. Auto-writing without confirmation pollutes the Brief with weakly-held framings. Never writing makes it stale. The propose-and-confirm pattern keeps the artifact trustworthy.

The operator may edit the Brief directly at any time. The raw markdown is exposed for power users; rendered-with-inline-edits is the default surface.

### 4.3 Why a Brief instead of pure-chat memory

Three reasons:

1. **Cross-chat continuity.** A new chat starts → AI reads the Brief → up to speed in one read. No mystery context, no opaque vector recall.
2. **Auditability.** The AI's "memory" of the site is a document the operator can read and correct.
3. **Multi-operator handoff.** Anyone working on the site inherits the same canonical understanding.

---

## 5. Two-Tier Memory Model

| Tier | What lives here | Lifetime | Access pattern |
|---|---|---|---|
| **Working memory** (chat-scoped) | Reference digests, screenshots, AI comparisons, the conversation itself | The chat session (durable, searchable) | Primer of last N chars in context; search tool for full history |
| **Crystallized memory** (site-scoped) | The Design Brief | The site | KMS summary + ToC + section-read tools |

Nothing is truly ephemeral. The chat history persists; digests persist with it; the Brief persists with the site. The two tiers differ in **what they hold** and **how the AI accesses them**, not in their durability.

By default chat search is scoped per-site — chats for site A do not surface when working on site B — to keep AI context clean.

---

## 6. Two Extraction Levels

The same fetcher feeds both. They differ in the post-processing.

### 6.1 Layer A — Signals (always)

Deterministic extractors run over the rendered page:

- Palette extraction with role inference.
- Typography detection from computed CSS.
- Layout / density / alignment signals.
- Imagery style classification.
- Content tree from semantic DOM.
- Asset inventory with content classification.

Output: the body of a Reference Digest, except for AI commentary and the summary, which are added by a follow-on LLM pass.

### 6.2 Layer B — Transcription (convert flow only)

The Layer A signals + the rendered DOM + screenshots are handed to a multimodal LLM call that produces a draft set of **module instances and theme tokens in the 1st contact schema**.

This is not deterministic parsing. It is the AI mapping "this hero with centered headline + image-right" onto our `hero-split` module with specific theme tokens. The transcription is mediated by [[DOC-7]]'s structured-edit discipline and the framework module catalog: the output must validate against the same schema as any operator-driven edit.

The result lands in the user's draft as an editable site. The operator then refines with the standard AI tool surface.

---

## 7. Display Surface

### 7.1 Primary — Digest report in the right panel

For the inspiration use case, the right panel shows the rendered Reference Digest report: screenshot strip, palette swatches, type sample, key messaging bullets, sitemap, AI commentary. The operator and the AI are looking at the same artifact (§3.1).

This sidesteps the iframe-blocking problem entirely. It also produces a richer, more readable surface than a raw embedded webpage — closer to a designer's presentation than a browser preview.

### 7.2 Secondary — Iframe with screenshot fallback

For operators who want to see the live site, an iframe view is available with a "click to open in a new tab" affordance. When the target site blocks framing (`X-Frame-Options`, `frame-ancestors`), the iframe falls back to a screenshot strip rendered through the same Browser Rendering pipeline.

### 7.3 Killer-demo progressive reveal

For the convert flow, latency is the demo. Single 60-second spinner is a weaker experience than progressive reveal even with identical end-state:

| Stage | Wall-clock | What the operator sees |
|---|---|---|
| 1 | 0–2s | Screenshot displayed, URL acknowledged |
| 2 | 2–8s | Layer A signals returned, theme tokens applied to a blank draft, palette and type visible |
| 3 | 10–60s | Layer B transcription completes, module instances populate the draft |
| Throughout | — | Operator AI is already conversing — "while I'm finishing the layout, what do you want to call the business?" |

The progressive reveal turns a slow operation into a magical one. The AI's ability to converse during the transcription is what makes this work.

---

## 8. Tool Surface (Sketch)

Exact schemas are deferred to REQ tickets. Likely tool surface:

| Tool (working name) | Purpose | Output |
|---|---|---|
| `search_references` | Web search for inspiration (e.g. "local plumber websites") | List of `{url, title, snippet}` |
| `analyze_page(url)` | Fetch + Layer A extraction; produces a digest | Reference Digest record + R2 asset keys |
| `transcribe_site(digest_id)` | Layer B — map a digest to module instances + theme tokens | Site Definition draft (per [[DOC-7]]) |
| `fetch_asset(url)` | Download a single asset to R2 | Asset record |
| `update_brief(diff)` | Propose an edit to the Design Brief | Diff for operator to confirm |

Each tool runs through [[DOC-8]]'s structured-edit pipeline. `transcribe_site` in particular must produce output that passes the same validator every other AI tool call uses ([[DOC-7]] §6.2 / [[DOC-8]] §6).

---

## 9. Document Shape (KMS-Aware From Day One)

A knowledge-management system providing **mechanical summaries**, **tables of contents**, and **section-read tools** is planned project-wide infrastructure. It does not exist yet, but designing the Brief and digest documents for it from day one costs nothing and avoids retrofit.

Both documents follow the shape:

```markdown
# {title}

> Summary: 1–2 paragraph distillation, AI-maintained.

## Table of contents
- Section A — one-line description
- Section B — one-line description

## Section A
...

## Section B
...
```

While the KMS is unavailable, the AI consumes whole documents directly. When the KMS arrives, summary extraction and section reads slot in with zero retrofit — the structure is already there.

Heavy assets — screenshots, asset images — stay out of these documents. They live in R2 and are referenced by markdown image syntax pointing at the asset key. The KMS indexes the references, not the bytes.

---

## 10. Implementation Surface

### 10.1 Static fetch path

Worker `fetch` against a target URL, parse with `linkedom` or `cheerio`. Sufficient for many sites (OG metadata, palette from inline CSS, headings, link graph) at near-zero cost. Always tried first.

### 10.2 JS-rendered path

Cloudflare Browser Rendering (`@cloudflare/puppeteer`) when the static path returns insufficient content (empty body, SPA shell, missing computed styles). Pays per browser-minute, so only used when needed.

The decision between static and rendered is itself a small heuristic — if the static fetch returns a near-empty document body relative to the document size, escalate. Detail in implementing REQs.

### 10.3 Storage layout

| Storage | What | Notes |
|---|---|---|
| R2 | Screenshots, downloaded assets | Referenced by key from digests and Brief |
| D1 / chat-history store | Chat messages, including embedded digest records | Per [[DOC-5]]'s data model |
| KV | Short-TTL response cache for `analyze_page` | Same URL fetched twice in a session should hit cache; cross-session cached briefly for freshness |
| Site-level store | The Design Brief markdown | Single markdown document per site, KMS-indexed when KMS exists |

### 10.4 Where it lives

All fetch tools execute from the `control-app` Worker as authenticated endpoints behind the AI tool surface. Never exposed publicly. Per-customer rate-limit policy applies (§11).

---

## 11. Safety Contract

External fetches are a clean SSRF and abuse surface. The contract:

- **No private IPs.** Reject targets resolving to RFC1918, loopback, link-local, or cloud-metadata ranges.
- **No `file://`, `gopher://`, etc.** HTTPS only; HTTP allowed only when explicitly upgraded from a previously-validated HTTPS host.
- **Redirect cap.** Maximum 5 redirects, each re-validated against the IP / scheme rules.
- **Size cap.** Hard limit on response body size; aborted past the cap.
- **Robots.txt respect.** Honored by default; an operator-confirmed override may exist for the convert use case where the operator is the site owner.
- **Per-customer rate limit.** Numbers TBD; enforced at the Worker layer.

These are non-negotiable from day one. Adding them later is harder than starting with them.

---

## 12. Out of Scope (v1)

| Item | Status |
|---|---|
| Cross-site cross-chat search | Default off; per-site only |
| "References library" / boards UI | Not in v1; scrollback + Brief cover this |
| Click-to-edit imported sites in the preview | Out of scope; AI-mediated only ([[DOC-8]] §9) |
| Multi-account aggregation | Out of scope |
| Non-markdown reference sources (Figma, Pinterest, PDF) | Out of scope v1; the digest schema is designed to accept them later |
| Crawl deeper than ~8 pages for inspiration, ~50 for convert | Out of scope |
| Direct site-to-site comparison features beyond what the AI synthesizes from digests | Out of scope |

---

## 13. Open Questions — Resolved

All questions originally listed here were closed during REQ scoping; resolutions live in the named REQs.

1. **Per-customer rate limits.** Resolved in [[REQ-20]]: 20 fetches per rolling hour; 100 per rolling day; burst limit of 10 in any 60-second window. All three windows enforced simultaneously.
2. **Browser Rendering budget.** Resolved in [[REQ-20]] / [[REQ-22]]: 50 browser-seconds per chat session; 200 browser-seconds per account per UTC day. Exhaustion falls back to static fetch with a typed note.
3. **Crawl depth caps.** Resolved: inspiration = 1 page per reference in v1 (the search-returned URL only — [[REQ-29]]'s decision section tightens the originally-proposed 8 to 1); convert = single URL transcription per call (multi-page convert deferred).
4. **KV cache TTLs.** Resolved in [[REQ-20]]: per-URL response cache 1-hour TTL keyed by `sha256(method|url|range)`; digest record cache 24-hour TTL ([[REQ-21]]); transcription results explicitly **not** cached ([[REQ-28]]).
5. **Search provider.** Resolved in [[REQ-29]]: Brave Search API for v1, behind a swappable `SearchProvider` interface.
6. **Transcription confidence reporting.** Resolved in [[REQ-28]]: per-module `confidence: 'high' | 'medium' | 'low'`. AI surfaces low-confidence modules in its post-transcription narrative; never refuses outright. Two validation failures trigger a hero-only fallback draft.
7. **Robots.txt override UX.** Resolved in [[REQ-20]] / [[REQ-28]]: per-origin per-chat operator confirmation. The convert-flow destructive modal in [[REQ-28]] folds the "I own this site" affordance into the same single confirmation.
8. **Brief size before KMS exists.** Resolved in [[REQ-27]]: target ≤ 16KB; consolidation hint at 32KB; consolidation gate at 64KB (further updates blocked until consolidated). Pre-KMS, the dispatcher inlines only the Brief summary + ToC, never the full body — the original [[CHAT-13]] turn 7 "stuff the whole thing into context" approach was superseded by [[DOC-10]] §5.2's tool-pattern alignment.
9. **Sparse-signal handling.** Resolved in [[REQ-21]]: every digest signal field is optional; absent fields serialize as `not_detected`; the AI commentary template includes a "What's missing" sub-section so absence is intentional content, not omission.

---

## 14. Related Tickets

- [[DOC-4]] — product vision
- [[DOC-5]] — platform architecture
- [[DOC-7]] — framework architecture principles
- [[DOC-8]] — builder UI architecture principles
- [[DOC-10]] — chat session persistence and AI memory (third memory surface model that the Brief integrates with)
- Implementation REQs:
  - [[REQ-20]] — Web fetch safety contract: SSRF guards, rate limiting, robots.txt, Browser Rendering budget
  - [[REQ-21]] — Reference Digest schema + static-fetch path + Layer A signal extractors
  - [[REQ-22]] — Browser Rendering integration: JS-rendered fetch path with screenshots and computed-CSS signals
  - [[REQ-27]] — Design Brief: per-site canonical memory markdown, propose-and-apply AI updates, builder Brief tab
  - [[REQ-28]] — Site Transcription (Layer B): convert flow from Reference Digest into module instances and theme tokens
  - [[REQ-29]] — Inspiration onboarding: search_references + compare_references tools + AI-led comparative discussion
- Underlying infrastructure (referenced by the above):
  - [[REQ-23]] — D1 schema for chat sessions + messages (FTS5) + reference docs
  - [[REQ-24]] — Chat session API + AI memory tools (tail-prime + search/read tools)
  - [[REQ-25]] — Builder UI for persistent chat sessions
  - [[REQ-26]] — Reference docs library + initial seed