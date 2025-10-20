# 🧠 Lesson 48 — Memory & Long-Context Architectures

### *AI Engineer Roadmap 2025 — Skill #48*

---

## 🎯 Objective

Learn how to give **AI models memory** — enabling them to recall prior interactions, maintain state across sessions, and process **long documents or conversations** efficiently using long-context architectures and vector memory systems.

---

## 🧩 Definition

**Memory** in AI systems allows models to retain useful context from previous inputs.
This can be **ephemeral** (short-term, in-context) or **persistent** (long-term, stored and retrieved).
Meanwhile, **long-context architectures** expand the model’s native token window (e.g., 128k–1M tokens in GPT-5 or Claude 3) to handle large-scale reasoning, documents, or codebases.

---

## 🧠 Core Concepts

| Concept                     | Description                                                                          |
| --------------------------- | ------------------------------------------------------------------------------------ |
| **Short-Term Memory (STM)** | Temporary context from current conversation (e.g., 8k–200k tokens).                  |
| **Long-Term Memory (LTM)**  | Stored facts retrieved on demand via embeddings or databases.                        |
| **Context Window**          | The maximum token size the model can “remember” in one session.                      |
| **Vector Memory**           | Semantic recall via similarity search instead of word-by-word recall.                |
| **Memory Compression**      | Summarization or clustering of old messages to save context tokens.                  |
| **Threaded Memory**         | Per-user or per-session state persistence.                                           |
| **Long-Context Models**     | Architectures like Gemini 1.5, Claude 3, and GPT-5 designed for massive input spans. |

---

## ⚙️ Example — Vector Memory with FAISS

```python
from langchain.vectorstores import FAISS
from langchain.embeddings import OpenAIEmbeddings

memory_texts = [
    "Mat lives in London.",
    "Mat is building AI tools for automation.",
    "Mat prefers dark mode and minimal UIs."
]

embeddings = OpenAIEmbeddings()
db = FAISS.from_texts(memory_texts, embeddings)

query = "Where does Mat live?"
docs = db.similarity_search(query, k=1)
print(docs[0].page_content)
```

---

## ⚙️ Example — Long-Context Prompting

```python
from openai import OpenAI
client = OpenAI()

context = open("research_notes.txt").read()
prompt = f"Summarize the key insights from this research:\n\n{context}"

response = client.chat.completions.create(
    model="gpt-5-128k",
    messages=[{"role": "user", "content": prompt}],
)
print(response.choices[0].message.content)
```

---

## 🧱 Types of Memory Systems

| Type                     | Example                                                      |
| ------------------------ | ------------------------------------------------------------ |
| **In-Context Memory**    | Conversation buffer (limited by token window).               |
| **Vector Memory**        | Stores and retrieves embeddings (FAISS, Pinecone, Chroma).   |
| **Summarized Memory**    | Compacts old conversations into short summaries.             |
| **File Memory**          | Uses disk-based archives to reload prior context.            |
| **Hybrid Memory**        | Combines in-context + vector-based recall.                   |
| **External Memory APIs** | LangChain Memory, OpenAI Assistants Threads, Vectara Memory. |

---

## 📘 Mini Project

**Goal:** Build a **Persistent Chat Memory System**
**Steps:**

1. Store user chat history as text in a vector DB.
2. On new queries, retrieve relevant past context.
3. Append retrieved snippets to the LLM prompt.
4. Summarize older history after 20 turns to maintain context size.

**Expected Outcome:**
A chatbot that “remembers” user preferences, goals, and facts across sessions without retraining the model.

---

## 🧠 Example Prompt

> “How does vector-based memory differ from transformer context windows, and why do modern LLMs combine both?”

---

## 🔍 Key Takeaway

Memory transforms LLMs into **context-aware agents** — able to reason across documents, maintain identity, and sustain coherent long-term conversations.

---

## 📚 Further Reading

* [LangChain Memory Components](https://python.langchain.com/docs/modules/memory/)
* [Anthropic Claude 3 Long Context Paper](https://www.anthropic.com/news/claude-3-family)
* [OpenAI GPT-5 128k Context Overview](https://platform.openai.com/docs/models)
* [Pinecone Vector Memory](https://docs.pinecone.io/)
* [Retrieval Memory with LlamaIndex](https://docs.llamaindex.ai/en/stable/module_guides/storing/memory.html)
