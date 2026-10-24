# Unit 4: Asynchronous Preparation & Diagnostic Drills
## Unstructured Text Ingestion & Dense Vector RAG

> **Time Commitment**: ~60 Minutes (Asynchronous Self-Study)  
> **Prerequisites**: Review of [Unit 4 Required Readings & Concepts](reading.md)  
> **Target Mastery**: Lexical vs. dense vector search, Cosine similarity math, ChromaDB HNSW indexing, Metadata filtering.

---

## 1. Readiness Self-Check Checklist
Before attempting the diagnostic drills below, verify you have completed the foundational preparation:
- [ ] Studied why keyword search fails on maintenance tickets using technical synonyms.
- [ ] Grasped the geometric meaning of dot products between L2-normalized embedding vectors.
- [ ] Verified local installation of `chromadb` and `sentence-transformers`.

---

## 2. Part 1: Foundational Concept Checks
Test your conceptual grasp of vector data engineering and RAG retrieval pipelines. Formulate your answer first, then click the bar to verify your reasoning against the architectural rationale.

<details>
<summary>Question 1: Why does Scikit-Learn TF-IDF fail when searching for synonyms?</summary>

**Architectural Rationale:**
TF-IDF is a lexical (bag-of-words) algorithm. It builds an orthogonal coordinate axis for every unique vocabulary token. 

If a mechanic's ticket describes `"whistling noise near turbine"` and the user searches for `"loud turbocharger squeal"`, the two documents share zero identical words. Their dot product in TF-IDF space is identically $0.0$, resulting in complete retrieval failure. Dense embeddings map semantic meaning into continuous vector space where synonymous concepts cluster together regardless of exact phrasing.
</details>

<details>
<summary>Question 2: What is the geometric formula for Cosine Similarity and why is L2 normalization critical?</summary>

**Architectural Rationale:**
Cosine similarity measures the angle between two vectors $\vec{u}$ and $\vec{v}$:
$$\text{Cosine Similarity} = \frac{\vec{u} \cdot \vec{v}}{\|\vec{u}\| \|\vec{v}\|}$$
When embedding vectors are L2-normalized such that their Euclidean norm $\|\vec{u}\| = 1.0$, the denominator becomes $1.0$, and cosine similarity reduces to a fast hardware dot product:
$$\text{Cosine Similarity} = \vec{u} \cdot \vec{v} = \sum_{i=1}^D u_i v_i$$
This enables sub-millisecond similarity scans using CPU SIMD instructions.
</details>

<details>
<summary>Question 3: How does ChromaDB's HNSW graph index prevent linear brute-force scan times?</summary>

**Architectural Rationale:**
Hierarchical Navigable Small World (HNSW) organizes high-dimensional vectors into multi-layer proximity graphs (analogous to a Skip List in data structures). 

The top layers have long-range sparse edges for rapid cross-cluster navigation, while the bottom layers have dense short-range edges for fine-grained nearest neighbor discovery. This reduces search complexity from linear $\mathcal{O}(N)$ brute-force comparison to logarithmic $\mathcal{O}(\log N)$, retrieving nearest vectors in under 2 milliseconds across millions of entries.
</details>

<details>
<summary>Question 4: What is the purpose of sliding window chunking with overlap in technical document ingestion?</summary>

**Architectural Rationale:**
If a long maintenance runbook is chunked into discrete 200-word blocks without overlap, critical diagnostic context that spans across the boundary of chunk 1 and chunk 2 is bifurcated and destroyed (e.g., error symptom in chunk 1, resolution in chunk 2). 

A sliding window with 15–20% overlap (e.g., 200-word chunks with a 40-word sliding step) guarantees that relational context spanning boundaries is preserved in at least one cohesive chunk.
</details>

---

## 3. Part 2: Code Execution Order & Syntax Traces

### Trace Drill 1: Metadata Pre-Filtering vs Post-Filtering
Examine the ChromaDB query below designed to find brake inspection tickets for Fleet Zone 2:

```python
import chromadb

client = chromadb.PersistentClient(path="./chroma_db")
collection = client.get_collection("maintenance_runbooks")

# Executing semantic retrieval with metadata constraints
results = collection.query(
    query_texts=["air pressure leak in brake lines"],
    n_results=5,
    where={"zone": 2}
)
```

<details>
<summary>Analyze the Query: Explain why passing where={"zone": 2} into collection.query() is dramatically superior to filtering results in Python afterwards.</summary>

**Diagnostic Analysis: PRE-FILTERING GRAPH PRUNING**
- If you retrieve the top 5 nearest neighbors without a `where` clause and filter in Python, all 5 returned results might belong to Zone 1 or Zone 3, leaving you with zero relevant results!
- Passing `where={"zone": 2}` enforces **pre-filtering**: ChromaDB prunes the HNSW candidate search space to only consider vectors tagged with `zone: 2` during graph traversal.
- This guarantees that all 5 returned results are both semantically relevant AND mathematically valid for Zone 2.
</details>

### Trace Drill 2: Embedding Ingestion Idempotency Bug
Examine the ingestion loop below designed to update a vector database from a directory of PDF reports:

```python
for doc in documents:
    collection.add(
        documents=[doc["text"]],
        metadatas=[doc["metadata"]],
        ids=[doc["ticket_id"]]
    )
```

<details>
<summary>Spot the Bug: What happens if this script is executed twice when new tickets are added to the directory?</summary>

**Diagnostic Analysis: DUPLICATE KEY TERMINATION**
- In ChromaDB, calling `.add()` with an existing `id` throws a fatal `ValueError: ID already exists` and crashes the pipeline midway!
- **Defensive Fix**: Use `.upsert()` instead of `.add()`:
  ```python
  collection.upsert(
      documents=[doc["text"]],
      metadatas=[doc["metadata"]],
      ids=[doc["ticket_id"]]
  )
  ```
  This makes the ingestion pipeline **idempotent**: existing records are updated, new records are inserted, and repeated runs complete without crashing.
</details>

---

## 4. Architecture Traps & Defensive Rules

<div style="background: #f8fafc; border-left: 4px solid #1e3a8a; padding: 1rem 1.25rem; margin: 1.5rem 0; border-radius: 0 4px 4px 0;">
  <h4 style="margin: 0 0 0.5rem 0; color: #1e3a8a;">The Three Golden Rules of Vector Data Pipelines:</h4>
  <ol style="margin: 0; padding-left: 1.25rem; line-height: 1.7;">
    <li><strong>Always Make Ingestion Idempotent:</strong> Always use <code>.upsert()</code> with deterministic document IDs to allow safe pipeline reruns.</li>
    <li><strong>Never Omit Structured Metadata:</strong> Always enrich text embeddings with structured metadata (date, equipment ID, author, zone) to enable high-precision pre-filtering.</li>
    <li><strong>Guard Against Out-of-Vocabulary Acronyms:</strong> Domain-specific acronyms (e.g. DEF, DPF, EGR) must be expanded or grounded in technical context to prevent embedding distortion.</li>
  </ol>
</div>

---

## 5. Preparation for Live In-Class Coding Clinic (Slot 2)
In the upcoming synchronous session, we will execute a live **"I Do, We Do" refactoring clinic**:
- **What to Have Open**: Terminal with Python 3.10+ activated, VS Code, and local Jupyter environment.
- **The Clinic Mission**: We will inspect Dr. Maya Lin's Scikit-Learn TF-IDF search prototype, observe its failure to match critical technical synonyms, and live-code a ChromaDB dense vector indexing pipeline retrieving the target resolution ticket at **Rank #1** with sub-2ms response time.
