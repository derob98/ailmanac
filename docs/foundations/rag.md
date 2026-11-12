# Retrieval-Augmented Generation (RAG)

> Source: https://derob98.github.io/ailmanac/docs/foundations/rag · AILmanac (CC BY 4.0)

Make any model answer about your data — and the failure modes to avoid.

<LevelBadge level="intermediate" />

<Callout type="objectives" items={[
  "What RAG is and the retrieve-augment-generate loop",
  "How to index, retrieve, augment, and generate with citations",
  "Why RAG beats fine-tuning for 'answer about my docs' needs",
  "The five failure modes that kill RAG quality",
  "A copy-paste grounding prompt that closes the two biggest gaps"
]} />

**RAG** makes a model answer questions about **your** data — docs, a knowledge base, a codebase — that it was never trained on. The idea is simple: **retrieve** the relevant pieces, **augment** the prompt with them, then **generate** an answer grounded in those pieces.

## The loop

```mermaid
flowchart LR
  Q[User question] --> R[Retrieve relevant chunks
  from your data]
  R --> A[Augment the prompt
  with those chunks]
  A --> G[Generate a grounded,
  cited answer]
```

<Steps items={[
  {title: "Index your data", body: "Split into chunks, embed them (see /docs/foundations/embeddings), and store in a vector (and/or keyword) index."},
  {title: "Retrieve", body: "Pull the top chunks most relevant to the question."},
  {title: "Augment", body: "Put those chunks in the prompt with an instruction like \"Answer only from the context below; if it's not there, say so.\""},
  {title: "Generate", body: "Produce the answer — and ideally cite which chunk each claim came from."}
]} />

For the embedding step in indexing, see [Embeddings & Vector Search](/docs/foundations/embeddings).

## Why RAG instead of fine-tuning?

<Callout type="tip" items={[
  "Fresh: update the data, not the model",
  "Verifiable: provides citations",
  "Cheap: far cheaper than retraining"
]} />

For most "answer about my documents" needs, RAG is the right first tool — see [Fine-tuning vs Prompting vs RAG](/docs/foundations/finetune-vs-prompt-vs-rag).

## The failure modes (where RAG quality dies)

<Callout type="warning" items={[
  "Bad retrieval = bad answer. If the right chunk isn't retrieved, the model can't use it. Most 'RAG is wrong' problems are retrieval problems.",
  "Chunking too coarse/fine wrecks relevance (see embeddings).",
  "No grounding instruction: the model blends retrieved facts with its own guesses. Tell it to answer only from context and to admit gaps.",
  "Stuffing too much: irrelevant chunks dilute the signal and cost tokens. Retrieve few, high-quality chunks.",
  "No citations: you can't verify, so you can't trust."
]} />

The chunking failure ties back to [embeddings](/docs/foundations/embeddings), and over-stuffing costs [tokens](/docs/foundations/tokens-and-context).

<Callout type="tip" items={[
  "Evaluate retrieval separately: measure 'did we retrieve the right chunk?' apart from 'did the model answer well?' It localizes the problem fast. See Evals (/docs/foundations/evals)."
]} />

## Copy-paste: a grounding prompt

The single highest-leverage fix is a grounding instruction. Drop your retrieved chunks into a template like this — it forces the model to answer *only* from context, cite each claim, and admit gaps instead of guessing:

<PromptCard title="Grounding prompt">{`You are answering strictly from the context below.

Rules:
- Use ONLY the context to answer. Do not use outside knowledge.
- Cite the source after each claim, like [chunk 2].
- If the answer is not in the context, reply exactly:
  "I don't have that in the provided sources."
- Quote numbers and names verbatim — never paraphrase a figure.

Context:
[chunk 1] ...
[chunk 2] ...
[chunk 3] ...

Question: <the user's question>`}</PromptCard>

Pair it with a *few* high-quality chunks (not everything you retrieved) and you close the two biggest gaps at once: hallucinated blending and unverifiable answers. Then [eval](/docs/foundations/evals) retrieval and generation separately so you know which half to tune.

## Master the terms

<Flashcards cards={[
  {front: "RAG", back: "Retrieve relevant pieces of your data, augment the prompt with them, then generate an answer grounded in those pieces."},
  {front: "Index step", back: "Split data into chunks, embed them, store in a vector and/or keyword index."},
  {front: "Augment step", back: "Put the retrieved chunks in the prompt with a grounding instruction: answer only from context, admit gaps."},
  {front: "Why RAG over fine-tuning", back: "Fresh (update data not model), provides citations, far cheaper than retraining."},
  {front: "#1 RAG failure mode", back: "Bad retrieval. If the right chunk isn't retrieved, the model can't use it — most 'RAG is wrong' problems are retrieval problems."},
  {front: "Grounding instruction", back: "Tell the model to answer ONLY from context, cite each claim, and say so when the answer isn't there."}
]} />

<Quiz title="Check yourself" questions={[
  {
    q: "What do the three letters in RAG stand for, in order?",
    options: ["Read, Analyze, Generate", "Retrieve, Augment, Generate", "Rank, Aggregate, Group", "Reduce, Append, Generate"],
    answer: 1,
    explain: "RAG = Retrieve relevant chunks, Augment the prompt with them, then Generate a grounded answer."
  },
  {
    q: "When 'RAG is wrong', what is most often the real problem?",
    options: ["The model is too small", "Retrieval — the right chunk wasn't pulled", "Too few tokens in the context window", "The embeddings are fine-tuned wrong"],
    answer: 1,
    explain: "Bad retrieval = bad answer. If the right chunk isn't retrieved, the model can't use it. Most 'RAG is wrong' problems are retrieval problems."
  },
  {
    q: "Why is RAG usually preferred over fine-tuning for 'answer about my documents'?",
    options: ["It makes the model larger", "It keeps knowledge fresh, gives citations, and is cheaper than retraining", "It removes the need for any prompt", "It guarantees the model never hallucinates"],
    answer: 1,
    explain: "RAG keeps knowledge fresh (update the data, not the model), provides citations, and is far cheaper than retraining."
  },
  {
    q: "What is the single highest-leverage fix to stop the model blending facts with guesses?",
    options: ["Retrieve every possible chunk", "A grounding instruction that forces answers only from context", "Increase the temperature", "Skip citations to save tokens"],
    answer: 1,
    explain: "A grounding instruction forces the model to answer only from context, cite each claim, and admit gaps instead of guessing."
  },
  {
    q: "Why evaluate retrieval separately from generation?",
    options: ["It is required by the model provider", "It localizes the problem fast — you know which half to tune", "It reduces token cost automatically", "Generation can't be measured otherwise"],
    answer: 1,
    explain: "Measuring 'did we retrieve the right chunk?' apart from 'did the model answer well?' localizes the problem fast and tells you which half to tune."
  }
]} />

<Callout type="takeaways" items={[
  "RAG = retrieve relevant chunks, augment the prompt, generate a grounded, cited answer.",
  "Index (chunk + embed + store), retrieve top chunks, augment with a grounding instruction, generate with citations.",
  "Prefer RAG over fine-tuning for document Q&A: fresh, cited, cheaper.",
  "Most failures are retrieval failures — retrieve few high-quality chunks, not everything.",
  "Always add a grounding instruction and cite; eval retrieval and generation separately."
]} />

## Next

- [Embeddings & Vector Search](/docs/foundations/embeddings)
- [Fine-tuning vs Prompting vs RAG](/docs/foundations/finetune-vs-prompt-vs-rag)
- [Research & Synthesis playbook](/docs/playbooks/research)
