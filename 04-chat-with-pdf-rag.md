# Project 4 - Chat with PDF

## What I Built

Built a Retrieval-Augmented Generation system capable of answering questions about uploaded PDFs.

---

## Architecture

PDF
↓
Extract Text
↓
Chunk
↓
Embeddings
↓
Similarity Search
↓
LLM
↓
Answer

---

## Biggest Things I Learned

- Embeddings represent semantic meaning.
- Similarity search retrieves relevant chunks.
- Chunking dramatically affects retrieval quality.
- Expensive computations should be cached.

---

## Mental Models

- Embeddings are coordinates, not summaries.
- Retrieval happens before generation.
- The LLM only answers using retrieved context.

---

## Biggest Mistakes

- Regenerated embeddings unnecessarily.
- Didn't initially understand cosine similarity.

---

## What I Can Build Now

- Document Q&A
- Resume analyzers
- Knowledge-base assistants
- Enterprise document search