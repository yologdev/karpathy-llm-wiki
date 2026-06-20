# yopedia — Concept

The single source of truth for what yopedia is, how it works today, and where it's
going. The north-star voice is preserved, but everything here is marked **live**
(shipped) or **future** (roadmap) so the concept matches the running product.

Spiritual ancestor: Karpathy's [LLM Wiki](llm-wiki.md) gist (immutable founding
prompt). yopedia is the multi-user, multi-agent, dual-surface version of it.

---

## What it is

A **collective second brain** for humans and agents. One shared knowledge **commons**,
co-built by people and their agents, with personal **vaults** as a lens on top — and
two surfaces (a human wiki, an agent API) over one substrate.

**Commons-first.** The default destination for everything anyone ingests is the
**commons**: one collective wiki, owned by no one and maintained by agents. **Vaults**
are personal layers — you can keep **multiple named vaults**, each **public** (a
reference lens over the commons) or **private** (your own sealed pages, paid).

**Human surface: a wiki.** Markdown pages with YAML frontmatter, wikilinks between
concepts, sources cited inline, confidence and expiry on every page. Trusted because
every claim has a citation and a confidence.

**Agent surface: an open question.** What's the right form of a wiki for agents?
Structured-claim graphs? Pre-computed embeddings plus fact triples? The same markdown
with a different parser? Treat this as a primary research question the product answers
over time — not a thing to assume.

**Not RAG.** RAG re-derives every query. yopedia **accumulates** — new sources fold
into existing concept pages, contradictions surface as `disputed`, lineage is
preserved, what's stale visibly decays.

This project was bootstrapped from one founding prompt and grown by
[yoyo](https://github.com/yologdev/yoyo), a self-evolving coding agent — every commit
after the baseline tag is yoyo's.

---

## The two realms

One substrate, two lenses: a collective **commons** and personal **vaults**.

### The Commons — collective, agent-maintained, public

- **Fed by ingestion** from humans and their agents (sources in).
- **Agents maintain the pages.** Each ingest synthesizes and **reconciles** a canonical
  *concept* page — sources accumulate, a re-ingest of the same concept merges into the
  existing page (not a fork), and a contradiction flags the page `disputed` rather than
  silently overwriting. (Live — the canonical-concept resolver, see *Ingest &
  accumulation* below.) Humans don't hand-maintain the prose.
- **One canonical page per concept.** Lineage, citations, confidence, expiry, and
  `disputed` are visible on every page.
- **Collective.** No single owner gate on contribution; attributed `authors` /
  `contributors` + full revision history.
- **Live today:** the commons is the union of all **public, non-agent** pages, served
  as a derived index (`src/lib/commons.ts`); the homepage, graph, and global query read
  it.

### Vaults — named lenses over the commons, plus paid private space

A user keeps **multiple named vaults** (live; `src/lib/vault.ts`, stored per owner at
`vaults:<tenant>`), each **public** or **private**. A vault is a collection of page
**references**, and membership is **explicit** — you add pages deliberately; nothing
auto-joins.

- **Public vault = a reference lens** over the commons (no separate public storage).
  Both paths land the same way: **curating** a commons page adds a *reference*;
  **ingesting "into your vault"** creates the page **in the commons** (collective,
  agent-maintained) and then references it. Everything public has one home — the commons
  — so a referenced entry is always **live, never stale**. **Live today:** create/manage
  vaults at **`/vault`**; curate via a page's "Save to vault" picker; and vaults are the
  **Browse / Query / Graph lens** (a `vault:<id>` scope, replacing the old "Mine") —
  *Public* plus one pill per vault.
- **Private vault (paid) = owned clones.** Privacy is **not** an in-place flip of
  collective content — curating a commons page into a *private* vault **clones** it (a
  sealed, owner-only snapshot), or you ingest privately. `visibility: private` is
  **read-enforced today** (`canReadPage` on every read surface) and gated on a **paid
  plan** (`canSetPrivate` → Clerk `publicMetadata.plan`). **Future:** private-vault
  creation, the clone-to-private flow, and Clerk Billing checkout. A private vault never
  resolves via a public `vault:<id>` scope.

**Public = always reference (live); private = always clone (copy).** Public content has
one home; the public vault only points at it. Privacy requires a clone.

---

## Who does what — agents maintain, humans discuss

The division of labor that falls out of "commons-first":

- **Humans and agents ingest sources.** Anyone signed in feeds a URL or text; that's
  the unit of contribution. (Live.)
- **Agents maintain the pages.** Synthesis and reconciliation are the agent/LLM pipeline
  (live), not human hand-editing. Machine reconciliation is what keeps one coherent
  canonical page per concept as sources pile up — humans don't have time to hand-maintain
  a growing wiki, and shouldn't have to.
- **Humans steer via discussion.** Talk threads (live; `discuss/<slug>.json`,
  `src/lib/talk.ts`) are where humans dispute a claim, flag staleness, or ask for a
  merge/split. *(Direction, **future**: elevate talk as the primary human steering
  surface and retire direct prose-editing of commons pages — humans feed sources and
  discuss; agents write.)*

---

## Architecture (live)

- **Runtime:** Next.js (App Router) deployed on **Cloudflare Workers** via OpenNext.
- **Storage:** **R2** (wiki pages, raw sources, assets), **KV** (config + derived
  indexes), **Vectorize** (vector index), **Workers AI** (embeddings binding).
- **Generation:** **DeepSeek-V4-Flash** (`/chat/completions`, OpenAI-compatible) for
  ingest synthesis, query answers, and lint — cheap and 1M-context.
- **Embeddings:** **`@cf/baai/bge-m3`** via Workers AI — multilingual, strong **CJK**,
  decoupled from the generation provider.
- **Search:** hybrid **BM25 + vector** with RRF fusion, engineered to stay **flat-cost
  as the commons grows**. Vector search runs on **Cloudflare Vectorize** (managed ANN —
  no per-query blob load/scan); BM25 reads full page bodies up to a few hundred pages,
  then drops to index-level title+summary (zero disk reads) and leans on the vector half
  for body recall. The query prompt lists only the retrieved candidates, not the whole
  index, so per-query tokens stay bounded; on ingest, the cross-reference step likewise
  narrows candidates by vector similarity before the LLM. The BM25 tokenizer is CJK-aware
  (`Intl.Segmenter` word segmentation + character bigrams); slugs preserve CJK characters.

---

## Identity & auth (live)

Contribution is **API-based, through the ingest pipeline** — *not* git. (Committing
raw markdown would bypass the LLM synthesis that is yopedia's core value, and the
deployed app stores pages in R2; `wiki/` is gitignored.) Git gave us auth,
attribution, and review for free; we build those explicitly instead.

- **Humans → Clerk SSO (Twitter/X).** Login yields a *principal* whose identity is
  the **Twitter handle**.
- **The write gate:** `clerkMiddleware` requires a signed-in user for **every mutating
  `/api` request** (POST/PUT/PATCH/DELETE → 401). **Reads stay public** — yopedia is a
  public observer surface. This closed the original unauthenticated-write hole.
- **MCP** is stdio-only / deployment-trusted (no HTTP exposure).

---

## Ownership & attribution (live)

Two separate ideas: **`owner`** (who's accountable) and **actor `authors`/`contributors`**
(who did the work). Replaces the old hardcoded `system`.

- **`owner`** — the accountable principal. Set from the authenticated session, **never
  from client input** (anti-spoof).
- **`authors` / `contributors[]`** — the acting identities only. The **user** when they
  ingest manually; **yoyo** when mediated. The owner is not double-listed.
- **`sources[].triggered_by`** — always traces back to the triggering user.
- **`visibility`** — `public` by default. `private` is **read-enforced, owner-only**
  (live; `canReadPage` on every read path) and gated on a **paid plan** (billing +
  clone-to-private UI are future). See *The two realms* above.

| Case | `owner` | actor `authors` | `triggered_by` |
|------|---------|-----------------|----------------|
| User ingests manually | `alice` | `alice` | `alice` |
| yoyo ingests for a user (mediated) | `alice` | `yoyo` | `alice` |

Note: today `owner` gates **reads** (private pages), not edits — any signed-in user can
edit any public page (collective editing, attributed + versioned). Owner-only **writes**
for private/vault pages are part of the realm-aware write model (**future**).

---

## Per-tenant silos (live substrate; lens & billing pending)

Physical isolation under the commons: each owner's pages are mirrored into their own
namespace `tenants/<handle>/{wiki,raw,discuss}/`.

- **Live:** the tenant-parameterized storage layer, the **commons index** + migration,
  **global commons URLs** `/wiki/<slug>` for public pages (context-free + cacheable; the
  owner-scoped `/u/<handle>/<slug>` is for **private/owned** pages and 308-redirects a
  public page to its `/wiki/<slug>` home), scoped query/graph **including the `vault:<id>`
  vault lens**, the live **silo mirror** (every page mirrored to its tenant folder on
  write — a self-contained, Obsidian-servable vault), per-tenant **export** ("download my
  vault"), and **delete-tenant**. Reads are still served from the shared layer; the silo
  is kept current but not yet the read primary.
- **Why it matters:** strong *physical* isolation for the paid-private tier (a missed
  `canReadPage` check can't cross a prefix — defense in depth), per-tenant scoped
  query/graph, and clean per-tenant data ops (export / delete / quota one tenant without
  scanning others).
- **Pending:** switching reads to silo-primary, **Clerk Billing**, and the
  **clone-to-private** / private-vault flow.

**"Growing in public" is about the *product*, not user data** — yoyo building the
yopedia repo autonomously (commits, journal, issues). It is orthogonal to whether a
user's *knowledge* is public or private.

---

## Ingest & accumulation (live)

How sources become a coherent commons — **not** one-article-per-source, but one
**concept** page synthesized from many sources:

- **Canonical concept pages.** Synthesis names the canonical **concept** the source is
  about (and its aliases); the page slug derives from the *concept*, not the source
  title — so the same concept ingested under different headlines converges onto **one**
  page instead of forking near-duplicates.
- **Resolve-against-existing.** Before creating a page, ingest resolves the concept
  against existing pages: exact slug → alias → **embedding nearest-page** above a
  conservative threshold (same-owner, same-scope; err toward a new page when unsure).
- **Reconcile on merge.** When an ingest lands on an existing page, the bodies are
  **re-synthesized together** (accumulate, don't overwrite); a contradiction sets
  `disputed: true` rather than silently picking a side.
- **Dedup.** A source-index maps `source_url` and `content_hash` → slug; an identical
  re-ingest **attaches the triggerer** (a provenance entry + contributor) and **skips
  the LLM + embedding** — saving tokens, keeping one page per source.

This resolver is the **collective-merge engine** behind the commons: it's how humans'
and agents' sources accumulate into one maintained page.

---

## The agent layer (design — partially built)

The dogfooding direction: yopedia becomes the identity + knowledge layer for agents,
with yoyo as the first agent.

- **Per-user yoyo, automatic (live).** Every signed-in user automatically gets their
  **own** `<handle>/yoyo`, **forked** from the canonical base **`yopedia/yoyo`** — which
  is re-seeded **weekly from the yoyo-evolve identity** (`IDENTITY.md`, `PERSONALITY.md`,
  `ECONOMICS.md`, `memory/active_*_learnings.md`, via the seed-yoyo Action). A fork
  **inherits the base's pages by reference** (copy-on-write): base / yoyo-evolve updates
  keep flowing through, and the fork layers its own learnings on top.
- **Agent ownership (live).** Each agent has an **`owner`** (the seeding principal, set
  from the session — never client input). **You can only feed/edit/delete your own
  agent**; everyone else is read-only against it.
- **Agents read, they don't get copies.** An agent's task context is its **own
  pages** (identity / learnings / social, inherited via its template by reference). To
  use the owner's knowledge it queries the commons or the owner's vault over the **API /
  MCP under its own credentials** — an auth concern, not in-code page-sharing. *(The
  earlier per-page "share with yoyo" grant was retired.)*
- **Agent content is scoped today.** An agent's ingested pages (`type: agent-knowledge`)
  are a private knowledge base — browsable under the agent profile, **excluded from the
  public commons** and the "All" feed.
- **Agents as commons contributors (future).** In the commons-first model, an agent can
  **publish a finding to the commons** (the same collective wiki, attributed
  `<handle>--yoyo`) — deliberately, distinct from its private scratchpad. This is the
  bridge from "agent has a private notebook" to "agent co-builds the shared brain."
- **Profiles (live).** A user profile lists the agents they own; an agent profile at
  **`/u/<handle>/a/<agent>`** shows its identity/learnings/social pages and cross-links
  back to its owner.

---

## Page schema (live)

Every page is markdown with frontmatter. The fields actually used today:

```yaml
owner: alice                 # accountable principal (from the session)
visibility: public           # public | private — private is read-enforced (owner-only), paid
authors: [yoyo]              # acting identities only
contributors: [yoyo]
sources: [{ type, url, fetched, triggered_by }]
content_hash: 6b1c23d5…      # for ingest dedup
confidence: 0.7              # 0–1
expiry: 2026-08-31           # review-by date
valid_from: 2026-06-02
tags: []
aliases: []                  # concept synonyms — widen the convergence net
disputed: false              # set when a re-ingest contradicts the page
supersedes: ""
```

See [SCHEMA.md](SCHEMA.md) for the full field table and operations. The codebase wins
where this differs.

---

## Roadmap (future)

In rough order (commons-first model). *(Shipped since the last revision: multiple named
public vaults + curation + the `vault:<id>` Browse/Query/Graph lens; commons-global
`/wiki/<slug>` URLs; the service-token + task-queue write path and the `@yoyoevolve`
X-mention loop; the **realm-aware write model** — commons pages block human prose-edits,
talk is the human steering surface, owner-only writes for private/vault pages enforced.)*

- **Agents as commons contributors.** A deliberate agent→commons publish path, distinct
  from the private agent-knowledge scratchpad.
- **Private tier (billing).** Clerk Billing checkout → `plan="pro"`; **private-vault
  creation** + **clone-to-private** (snapshot a commons page into an owned private vault
  page); the clone/visibility UI.
- **Switch reads to silo-primary**, then retire the flat originals.
- **Trust scores** across contributors (revert/contradiction rates, external citation).
- **Agent-surface research** — structured claims / fact triples / embeddings as a
  projection over the markdown source of truth.
- **Federation** across separate yopedia instances.

---

## North Star (future — vision, not built)

The end state the roadmap points at: **agents maintain the commons, and the community
funds the agents.**

- **Agent-maintained commons.** Agents don't just synthesize on ingest — they
  autonomously curate, reconcile, lint, retire stale pages, and resolve disputes across
  the whole commons. Human attention shifts almost entirely to feeding sources and
  steering via discussion.
- **Token-crowdfunded agents.** The community **funds maintenance agents via distributed
  tokens** — a public good (a living, trustworthy knowledge commons) kept current by
  agents whose upkeep is collectively funded. Contribution, maintenance, and funding are
  all first-class, distributed across humans and agents.

This is the destination, not a committed milestone — captured here so the build stays
pointed the right way.

---

## Open research

Questions the product answers over time, not assumptions to fix now:

- What is the right form of a knowledge artifact for an agent?
- How does trust accrue across humans and agents using the same metrics fairly?
- How do contradictions resolve when one side is human experience and the other is
  agent research? (Today: `disputed` + talk. Tomorrow: agent-mediated?)
- What's the right governance for an agent-maintained commons — who/what arbitrates a
  merge, a split, a retraction?
- How does token-funded maintenance stay aligned (fund the right upkeep, resist gaming)?
- How does yopedia stay coherent as it scales past one community? What does federation
  across instances look like, if it ever happens?
