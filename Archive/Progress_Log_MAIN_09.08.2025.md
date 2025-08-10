# 📊 Progress Log — AI Financial Assistant (RAG-Based)

> Goal: Build a RAG system that answers user questions based on the book *The 6-Step Personal Finance Reset*.

---

## ✅ Phase 1: Knowledge Base Preparation — **Completed**

- [x] 📘 **Created original source material** — *"The 6-Step Personal Finance Reset"*, developed specifically for this project as both:  
  1. A standalone commercial product.  
  2. An AI-ready structured knowledge base for RAG.

  Subtasks:
  - [x] 🔍 Conducted market research to identify audience needs, niche opportunities, and bestseller potential.
  - [x] 🛠 Designed the book’s dual purpose from the outset — monetizable asset + structured AI dataset.
  - [x] 📑 Created a logical content structure — chapters, subchapters, checklists, frameworks — optimized for future semantic chunking.
  - [x] ✍ Used AI-assisted writing techniques, followed by human editing and restructuring for clarity and educational impact.
  - [x] 🧠 Applied principles of behavioral psychology to make advice practical, emotionally supportive, and easy to implement.
  - [x] ⏱ Completed the creation process in approximately 4–6 hours of focused work.

**Extended Commentary:**  
The knowledge base was not simply “prepared” in the technical sense — it was **conceived and built as a multi-purpose asset** from the ground up.  
Before writing, a targeted market analysis was conducted to ensure the content would address clear audience pain points and have strong commercial potential. The book’s structure was deliberately designed to serve **both as a retail-ready product** and **as a semantically organized dataset** for RAG integration.  

The content balances **technical guidance with emotional and behavioral insights**, ensuring that recommendations are easy to follow and sustainable in real life. This required combining skills in **information design, human behavior, and AI-assisted content creation**. By doing so, one creative effort produced **multiple benefits**: a knowledge base, a marketable product, and a reusable educational framework.


---

## ✅ Phase 2: Data Processing & Indexing — (**completed;** later issues found)

**Issues identified (after completion):**
- Chunk boundaries were incorrect: some chunks start mid-chapter and end in a different chapter/subchapter.
- As a result, certain embeddings represent mixed/unrelated content, degrading retrieval precision and ranking stability.

**Required corrections:**
- [ ] Re-chunk strictly within chapter/subchapter boundaries.
- [ ] Target chunk size **350 ± 50 GPT tokens** with **~15% soft overlap**.
- [ ] Fix/normalize metadata, regenerate embeddings.
- [ ] Create a new Chroma collection **`finance_book_v4`**; keep **`finance_book_v2`** and **`finance_book_v3`** for rollback and A/B comparison.

**Previously completed work (unchanged):**

- [x] 📄 **Extracted text from Word-Book** — converted the manuscript into a clean, machine-readable `.txt` file for consistent downstream processing.  
- [x] 🧩 **Semantic chunking** — split content into meaning-preserving segments using cosine similarity between sentence-transformer embeddings (`all-MiniLM-L6-v2`). This ensured that each chunk contained a coherent unit of thought.  
- [x] 🧮 **Token count & chunk size adjustment** — pre-calculated the number of tokens in each chunk using `tiktoken` (GPT-4.0 tokenizer) to enforce a **300–500 token range**. This was done *before* embeddings to:
  1. Guarantee that each chunk fits comfortably within ChatGPT-4.0’s context window.
  2. Avoid overly small or excessively large chunks, which could harm retrieval quality.  
  *(Note: This is not the same as the model’s own tokenization step — it was a preparatory measurement for optimal chunk sizing.)*  
- [x] 🔗 **Embedding generation** — encoded each chunk using the `thenlper/gte-large` model (1024-dimensional vectors), chosen for high semantic retrieval accuracy in English-language finance content.  
- [x] 🏷 **Metadata enrichment** — attached metadata to each chunk, including:
  - Chapter title
  - Sequential order in the book
  - Token count
  - Character start/end offsets in the original text  
  This enables **filtering, chapter-level navigation, and neighbor-aware retrieval**.  
- [x] 📦 **Vector database creation** — stored all chunks with embeddings and metadata in a **persistent ChromaDB** instance (`./chroma_store`) for fast, local semantic search without API costs or latency.

**Extended Commentary:**  
Phase 2 transformed a raw manuscript into an **LLM-ready knowledge index**.  
The process began with semantic chunking — identifying natural conceptual boundaries rather than cutting text blindly by character length. This preserved the author’s logic and ensured that each chunk could serve as a self-contained retrieval unit.  

A critical intermediate step was **pre-tokenization measurement**: before embeddings were created, each chunk was analyzed with the GPT-4.0 tokenizer to ensure it fit within the 300–500 token range. This range was chosen as the “sweet spot” for ChatGPT-4.0 RAG pipelines: large enough to carry full ideas, but small enough to combine multiple chunks in one context window.  

The embedding step used `thenlper/gte-large` — a high-quality, open-source model that runs locally, removing dependency on external APIs and giving control over the vector store. Every chunk was enriched with metadata to allow for **intelligent retrieval** (e.g., only from certain chapters, or with neighbor chunks for added context).  

Finally, the fully processed dataset was loaded into a persistent ChromaDB, creating a reusable, query-ready vector index. With this, the knowledge base can now be searched semantically in milliseconds, forming the backbone of the retrieval-augmented generation system for Phase 3.

---

## 📅 Phase 3: Retriever Development — **Planned**

## Phase 3 — Retriever Development (**in progress; paused pending Phase 2.1**)

**Work completed so far:**
- [x] Implemented **BM25** retriever.
- [x] Implemented **Hybrid** retriever (**BM25 + dense embeddings**) with **Reciprocal Rank Fusion (RRF)**.
- [x] Ran initial retrieval tests on collections **`finance_book_v2`** / **`finance_book_v3`**.

**Issue discovered:**
- Retrieval quality is limited by **flawed chunking from Phase 2** (cross-chapter chunks; embeddings mixing unrelated content).

**Decision:**
- **Pause Phase 3** and execute **Phase 2.1 — Rechunking** to fix boundaries, correct metadata, regenerate embeddings, and create **`finance_book_v4`**.
- After **2.1**, **resume Phase 3** on the clean **v4** dataset and re-run evaluation/tuning.

**Previously planned scope (unchanged):**

- [ ] Implement **Hybrid Search** (BM25 + embeddings) for initial retrieval.
- [ ] Prepare a **training dataset** (question → correct chunk) for retriever fine-tuning.
- [ ] Fine-tune a **dense retriever** to improve semantic search accuracy.
- [ ] Save and integrate retriever into the RAG pipeline.

---

## 📅 Phase 4: LLM Integration — **Planned**

- [ ] Choose a suitable LLM (GPT-4, Mistral, Claude, etc.).
- [ ] Build a RAG pipeline (LangChain / Haystack).
- [ ] Design system prompts, tone, and style guidelines.
- [ ] Test retrieval + generation flow with real financial queries.

---

## 📅 Phase 5: User Interface / API — **Planned**

- [ ] Develop a simple interface (Streamlit / Gradio / FastAPI).
- [ ] Add question input and generated answer display.
- [ ] Show retrieved context chunks for transparency.
- [ ] Allow follow-up / clarifying questions.

---

## 📅 Phase 6: Testing & Optimization — **Planned**

- [ ] Test system with real-world scenarios based on book content.
- [ ] Measure retrieval accuracy, relevance, and response time.
- [ ] Optimize retriever, embeddings, and prompts.
- [ ] Collect feedback and iterate.

---

## 📅 Phase 7: Documentation & Release — **Planned**

- [ ] Write README.md with project architecture and usage instructions.
- [ ] Provide Colab / Jupyter notebook for local testing.
- [ ] Package and demo the final system.
