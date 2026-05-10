# 📓 NotebookLM Clone — RAG-Powered Document Chat

> Upload any PDF or text file and have a conversation with it. Answers are grounded exclusively in your document — no hallucinations, no guessing.

![Next.js](https://img.shields.io/badge/Next.js-14-black?style=flat-square&logo=next.js)
![TypeScript](https://img.shields.io/badge/TypeScript-5-blue?style=flat-square&logo=typescript)
![Gemini](https://img.shields.io/badge/Gemini_API-Free-4285F4?style=flat-square&logo=google)
![Qdrant](https://img.shields.io/badge/Qdrant-Cloud_Free-red?style=flat-square)
![Vercel](https://img.shields.io/badge/Deployed_on-Vercel-black?style=flat-square&logo=vercel)

---

## 📌 Table of Contents

- [Overview](#-overview)
- [Live Demo](#-live-demo)
- [Tech Stack](#-tech-stack)
- [RAG Pipeline](#-rag-pipeline)
- [Chunking Strategy](#-chunking-strategy)
- [Project Structure](#-project-structure)
- [Local Setup](#-local-setup)
- [Deployment](#-deployment-to-vercel)
- [How to Use](#-how-to-use)
- [Marking Scheme](#-marking-scheme)

---

## 🧠 Overview

This is a full-stack **Retrieval-Augmented Generation (RAG)** application — a clone of [Google NotebookLM](https://notebooklm.google.com/). It lets users upload documents and ask natural language questions about them.

Unlike a plain chatbot, this app **never answers from the LLM's memory**. Every answer is sourced directly from the uploaded document, with citations showing which chunks were used.

**What it does, end-to-end:**

1. User uploads a PDF or `.txt` file
2. The system extracts the text, splits it into overlapping chunks, and embeds each chunk using Gemini's embedding model
3. Embeddings are stored in a Qdrant vector database in the cloud
4. When the user asks a question, the question is embedded and the most semantically similar chunks are retrieved
5. Those chunks are injected into a strict system prompt, and Gemini generates a grounded answer
6. The answer is shown in a chat UI along with source citations

---

## 🛠 Tech Stack

| Layer | Tool | Why |
|---|---|---|
| **Frontend** | Next.js 14 (App Router) + TypeScript | Full-stack React with API routes built in |
| **Styling** | Tailwind CSS | Utility-first, fast to build clean UIs |
| **LLM** | Google Gemini `gemini-2.0-flash` | Free tier via AI Studio, fast and capable |
| **Embeddings** | Google Gemini `text-embedding-004` | Free, 768-dim, optimized for retrieval tasks |
| **Vector DB** | Qdrant Cloud (free tier) | Persistent cloud vector store, 1GB free |
| **PDF Parsing** | `pdf-parse` (npm) | Reliable text extraction from PDFs |
| **Deployment** | Vercel (free tier) | One-click deploys from GitHub, zero config |

**Cost: $0** — every service used has a free tier. No credit card required for the Google API key.

---

## 🔄 RAG Pipeline

The application implements a complete two-phase RAG pipeline:

### Phase 1 — Ingestion (on document upload)

```
┌─────────────┐
│  User uploads│
│  PDF / TXT  │
└──────┬──────┘
       │
       ▼
┌─────────────────────┐
│  Extract Raw Text   │
│  pdf-parse / UTF-8  │
└──────────┬──────────┘
           │
           ▼
┌──────────────────────────┐
│  Recursive Character     │
│  Chunking                │
│  size=800, overlap=150   │
└──────────┬───────────────┘
           │
           ▼
┌──────────────────────────┐
│  Gemini text-embedding   │
│  -004 → 768-dim vectors  │
│  (RETRIEVAL_DOCUMENT)    │
└──────────┬───────────────┘
           │
           ▼
┌──────────────────────────┐
│  Qdrant Cloud            │
│  Upsert all chunk vectors│
│  + metadata payload      │
└──────────────────────────┘
```

### Phase 2 — Retrieval + Generation (on each question)

```
┌──────────────────┐
│  User asks a     │
│  question        │
└────────┬─────────┘
         │
         ▼
┌──────────────────────────┐
│  Gemini text-embedding   │
│  -004 → query vector     │
│  (RETRIEVAL_QUERY)       │
└──────────┬───────────────┘
           │
           ▼
┌──────────────────────────┐
│  Qdrant cosine search    │
│  → top 5 similar chunks  │
└──────────┬───────────────┘
           │
           ▼
┌──────────────────────────┐
│  Build strict system     │
│  prompt with chunks as   │
│  context                 │
└──────────┬───────────────┘
           │
           ▼
┌──────────────────────────┐
│  Gemini gemini-2.0-flash │
│  temperature=0.2         │
│  → grounded answer       │
└──────────┬───────────────┘
           │
           ▼
┌──────────────────────────┐
│  Return answer + source  │
│  citations to UI         │
└──────────────────────────┘
```

---

## ✂️ Chunking Strategy

### Strategy: Recursive Character Splitting

**Parameters:**
- `chunkSize`: 800 characters
- `chunkOverlap`: 150 characters
- Minimum chunk length: 50 characters

**How it works:**

The chunker uses a cascading delimiter approach. It tries to split text at the largest natural boundary first, and only falls back to smaller delimiters if a chunk is still too large:

```
Priority 1: "\n\n"   → paragraph breaks (most natural boundary)
Priority 2: "\n"     → line breaks
Priority 3: ". "     → sentence endings
Priority 4: " "      → word boundaries (last resort)
```

**Why this strategy?**

Splitting at paragraph boundaries (`\n\n`) preserves the semantic coherence of ideas. A paragraph in a document is usually one complete thought — keeping it together means retrieval picks up entire ideas rather than mid-sentence fragments.

The 150-character overlap between adjacent chunks ensures that sentences spanning two chunks aren't lost. Without overlap, a question about content that happens to fall at a chunk boundary would fail to retrieve the right context.

**Why 800 characters?**

This is roughly 120–160 words — long enough to contain a complete idea with context, short enough that the retrieved chunks don't flood the LLM context window. At k=5 chunks retrieved, the total injected context is at most ~4,000 characters, well within Gemini's limits.

**Example:**

Given a 2,400-character paragraph, the chunker produces:
- Chunk 0: characters 0–800
- Chunk 1: characters 650–1450 (starts 150 chars before chunk 0 ends)
- Chunk 2: characters 1300–2100
- Chunk 3: characters 1950–2400

Each chunk is stored with metadata: `{ source, chunkIndex, pageApprox }`.

---

## 📁 Project Structure

```
notebooklm-clone/
├── app/
│   ├── page.tsx                  # Main layout — upload + chat panels
│   ├── layout.tsx                # Root layout with fonts and metadata
│   ├── globals.css               # Tailwind base styles
│   └── api/
│       ├── upload/route.ts       # POST /api/upload — full ingestion pipeline
│       └── chat/route.ts         # POST /api/chat — retrieval + generation
│
├── lib/
│   ├── gemini.ts                 # Gemini client: embedText() + generateAnswer()
│   ├── qdrant.ts                 # Qdrant client: createCollection(), upsert, search
│   ├── chunker.ts                # Recursive character splitting logic
│   └── pdf.ts                   # PDF and TXT text extraction
│
├── components/
│   ├── UploadSection.tsx         # Drag-and-drop upload with step-by-step status
│   ├── ChatSection.tsx           # Chat history + input bar
│   └── MessageBubble.tsx         # Individual message with collapsible sources
│
├── types/
│   └── index.ts                  # Shared TypeScript interfaces
│
├── .env.local.example            # Template — copy to .env.local
├── .gitignore
├── next.config.ts
├── tailwind.config.ts
├── tsconfig.json
├── package.json
└── README.md
```

---

## 🚀 Local Setup

### Prerequisites

- Node.js 18 or later
- A Google AI Studio account (free, no credit card)
- A Qdrant Cloud account (free, no credit card)

---

### Step 1 — Clone the repository

```bash
git clone https://github.com/your-username/notebooklm-clone.git
cd notebooklm-clone
```

### Step 2 — Install dependencies

```bash
npm install
```

### Step 3 — Get your Google API Key (free)

1. Go to [aistudio.google.com](https://aistudio.google.com)
2. Sign in with your Google account
3. Click **"Get API Key"** → **"Create API key"**
4. Copy the key — it starts with `AIzaSy...`

> The free tier gives you 15 requests/minute and 1 million tokens/day. More than enough for this project.

### Step 4 — Set up Qdrant Cloud (free)

1. Go to [cloud.qdrant.io](https://cloud.qdrant.io) and sign up (free)
2. Click **"Create Cluster"** → choose the **Free tier** → select any region → click **Create**
3. Once the cluster is ready, go to the **API Keys** tab and click **"Create API Key"**
4. From the cluster overview, copy your **Cluster URL** (looks like `https://xxxx.us-east4-0.gcp.cloud.qdrant.io`)

### Step 5 — Configure environment variables

```bash
cp .env.local.example .env.local
```

Open `.env.local` and fill in your values:

```env
GOOGLE_API_KEY=AIzaSy...           # From Google AI Studio
QDRANT_URL=https://xxxx.gcp.cloud.qdrant.io   # From Qdrant Cloud cluster
QDRANT_API_KEY=eyJhbGci...         # From Qdrant Cloud API Keys tab
```

> ⚠️ Never commit `.env.local` to Git. It is already listed in `.gitignore`.

### Step 6 — Run the development server

```bash
npm run dev
```

Open [http://localhost:3000](http://localhost:3000) in your browser.

---

## ☁️ Deployment to Vercel

### Step 1 — Push to GitHub

Make sure your repository is public (required for the assignment submission):

```bash
git add .
git commit -m "initial commit"
git push origin main
```

### Step 2 — Import on Vercel

1. Go to [vercel.com](https://vercel.com) and sign in with GitHub
2. Click **"New Project"** → import your repository
3. Vercel auto-detects Next.js — no configuration needed

### Step 3 — Add environment variables

In the Vercel project dashboard:

1. Go to **Settings → Environment Variables**
2. Add all three variables:
   - `GOOGLE_API_KEY`
   - `QDRANT_URL`
   - `QDRANT_API_KEY`

### Step 4 — Deploy

Click **Deploy**. Your app will be live at `https://your-project.vercel.app` in under two minutes.

> ⚠️ Vercel serverless functions have a 10-second default timeout on the free plan. Large PDFs (100+ pages) may require the `maxDuration` setting in `next.config.ts`, which is already configured.

---

## 💬 How to Use

1. **Open the app** at your live URL or `localhost:3000`
2. **Upload a document** — drag and drop a PDF or `.txt` file onto the left panel, or click to browse. Max size: 10MB.
3. **Wait for processing** — you'll see step-by-step status as the document is chunked, embedded, and stored. This takes 10–30 seconds depending on document size.
4. **Ask a question** — type any question about your document in the chat input on the right and press Enter or click Send.
5. **Read the answer** — the AI responds with an answer grounded in your document. Click **"Show Sources"** under any answer to see which chunks were retrieved and their approximate page numbers.
6. **Upload a new document** — click "Upload New Document" to start over with a different file.

**Tips for best results:**
- Ask specific questions ("What does the document say about X?") rather than vague ones
- If an answer seems incomplete, try rephrasing your question
- The app will explicitly tell you if it can't find the answer in your document

---

## 📊 Marking Scheme

| Criterion | Marks | Where Implemented |
|---|---|---|
| **GitHub Repository** | 2 | This public repo |
| **Live Project** | 2 | Deployed on Vercel (link above) |
| **RAG Pipeline** — chunking → embedding → retrieval → generation | 3 | `lib/chunker.ts`, `lib/gemini.ts`, `lib/qdrant.ts`, `app/api/upload/route.ts`, `app/api/chat/route.ts` |
| **Answer Quality** — grounded in document, not hallucinated | 2 | Strict system prompt in `app/api/chat/route.ts` — LLM is explicitly forbidden from using outside knowledge |
| **Code Quality & Documentation** | 1 | TypeScript strict mode, JSDoc comments, this README |
| **Total** | **10** | |

---

## 🔒 Key Design Decisions

**Why not use LangChain?**
This project implements the RAG pipeline from scratch using the raw Gemini and Qdrant SDKs — exactly as the assignment's starter code demonstrates. This makes the pipeline transparent and easier to understand and grade.

**Why Gemini instead of OpenAI?**
The Google AI Studio free tier requires no credit card and gives generous rate limits. The `text-embedding-004` model produces 768-dimensional vectors with strong retrieval performance, and `gemini-2.0-flash` is fast and accurate for document Q&A.

**Why Qdrant Cloud instead of local Qdrant?**
Local Qdrant (`localhost:6333`) cannot be used in a deployed app. Qdrant Cloud's free tier provides a persistent cluster that survives across requests, making it ideal for a live deployment.

**Why temperature=0.2?**
Lower temperature reduces creative variation in the LLM's output, which is desirable here — we want factual, conservative answers that stay close to the source text, not creative paraphrasing.

---

## 📄 License

MIT — free to use, modify, and submit for educational purposes.
