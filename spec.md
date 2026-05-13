# spec.md — AI-Based Desktop Help

## Purpose

Create an AI-powered assistant that answers questions about using Ubuntu. The user asks a natural-language question; the app retrieves relevant chunks from the local markdown-based Ubuntu documentation, feeds them to a local LLM, and returns an answer plus links to relevant doc pages.

This is a local-first, context-based, offline tool. It uses official Ubuntu docs as its knowledge base and integrates optionally into GNOME Shell's overview search.

The minimum viable product is a CLI. A stretch goal is an integration with GNOME shell overview search.

---

## Scope

### In scope

- Cloning and keeping Ubuntu Desktop docs up-to-date locally
- Chunking and embedding markdown documentation files into a local vector database
- Answering user questions via a CLI interface
- Returning a generated answer, a link to the relevant local doc page, and optionally a clarifying question
- Ubuntu version awareness (e.g. a user on 22.04 gets answers from 22.04 docs)
- GNOME Shell search provider integration (stretch goal)
- Agentic actions offering to perform the described task on the user's behalf (stretch goal)

### Out of scope

- Cloud-based LLM backends (local-first; cloud as opt-in future extension)
- Support for non-Ubuntu/non-GNOME desktops
- General web search or crawling beyond official Ubuntu docs
- Fine-tuning or training models

---

## Architecture

```
┌─────────────────────────────────────────────────────┐
│                   User Interface                    │
│         CLI (clap)  /  GNOME Shell Search           │
└───────────────────┬─────────────────────────────────┘
                    │ query
┌───────────────────▼─────────────────────────────────┐
│                  Query Pipeline                     │
│  1. Embed query (fastembed)                         │
│  2. Search vector DB (LanceDB)                      │
│  3. Retrieve top-k chunks + source paths            │
└───────────────────┬─────────────────────────────────┘
                    │ chunks + metadata
┌───────────────────▼─────────────────────────────────┐
│                  LLM Layer                          │
│  Prompt = system instructions + chunks + query      │
│  LLM generates: answer + clarifying question        │
│  Returns: answer, doc links, optional question      │
└───────────────────┬─────────────────────────────────┘
                    │ structured response
┌───────────────────▼─────────────────────────────────┐
│               Agentic Layer (stretch)               │
│  Parses intent → proposes action → awaits consent   │
│  Executes via D-Bus / gsettings / shell             │
└─────────────────────────────────────────────────────┘
```

---

## Components

### 1. Doc Syncer

- Clones the Ubuntu Desktop documentation Git repository locally
- Detects Ubuntu version on the host machine
- On startup (or on demand), pulls latest changes
- Stores docs under a versioned path (e.g. `~/.local/share/desktop-help/docs/24.04/`)

### 2. Indexer

- Walks the local doc directory for `.md` files
- Parses markdown with `pulldown-cmark`, strips markup, preserves structure
- Chunks text using `text-splitter` with token-aware splitting
- Embeds each chunk with `fastembed` (downloads small embedding model on first run)
- Stores chunks + vectors + source file path + Ubuntu version tag in LanceDB
- Re-indexes only changed files (content hash or git diff)

### 3. Query Engine

- Embeds the user's query with the same embedding model
- Queries LanceDB for top-k semantically similar chunks, filtered by Ubuntu version
- Returns chunks with their source file paths

### 4. LLM Interface

- Constructs a prompt: system message + retrieved chunks + user query
- Sends request to local LLM via one of:
  - **Option A**: `llama-cpp-rs` (self-contained, preferred for snap packaging)
  - **Option B**: Ollama HTTP API (easier to develop against)
  - **Option C**: Canonical inference snap HTTP API
- Parses response into structured output: `{ answer, doc_links, clarifying_question? }`

### 5. CLI Frontend

- Built with `clap`
- Commands:
  - `desktop-help ask "<question>"` — single-shot query
  - `desktop-help chat` — interactive session
  - `desktop-help index` — manually trigger re-indexing
  - `desktop-help update` — pull latest docs
- Renders answer in terminal, prints doc links as clickable file:// URIs

### 6. GNOME Shell Search Provider (stretch)

- Implements `org.gnome.Shell.SearchProvider2` D-Bus interface
- Triggered by `??` or `ask:` prefix in GNOME overview search
- Registered via a `.service` file for D-Bus autostart
- Returns results as GNOME search result items; clicking opens the doc or a response window

### 7. Agentic Layer (stretch)

- Detects actionable intents in the user query (e.g. "change my wallpaper")
- Presents proposed action to user and requests confirmation
- Executes via `gsettings`, `gio`, D-Bus calls, or shell commands
- Logs actions taken

---

## Key Dependencies

| Purpose | Crate / Tool |
|---|---|
| CLI | `clap` |
| Markdown parsing | `pulldown-cmark` |
| Text chunking | `text-splitter` + `tokenizers` |
| Embeddings | `fastembed` |
| Vector database | `lancedb` |
| LLM (option A) | `llama-cpp-rs` |
| LLM (option B) | Ollama HTTP API (`reqwest`) |
| LLM (option C) | Canonical inference snap HTTP API |
| GUI / GNOME bindings | `gtk-rs` (if GUI needed) |
| D-Bus | `zbus` |

---

## Data Model

### Vector DB record

```
{
  id: uuid,
  ubuntu_version: "24.04",
  source_file: "how-to/change-wallpaper.md",
  chunk_index: 3,
  chunk_text: "...",
  vector: [f32; N],
  content_hash: "sha256:...",
}
```

### LLM response

```
{
  answer: String,
  doc_links: Vec<(title: String, path: String)>,
  clarifying_question: Option<String>,
}
```

---

## Ubuntu Version Awareness

- At startup, read `/etc/os-release` to determine the current Ubuntu version
- Tag all indexed chunks with the detected version
- Filter vector search by version tag
- Future: allow the user to override the version (e.g. for testing or cross-version queries)

---

## Non-Goals (for now)

- A full GUI app (CLI first; GTK GUI is a future iteration)
- Multi-user or networked deployments
- Fine-tuning, RLHF, or feedback collection pipelines (noted as a future idea)
- Support for languages other than English

---

## Constraints

- Must work on laptops without a dedicated GPU
- Prefer small models (e.g. TinyLlama, Phi-3-mini) for performance
- All model downloads and DB writes go to user-local directories (no root required)
- Snap packaging must be feasible (no hard dependencies on system Python or system libs)
