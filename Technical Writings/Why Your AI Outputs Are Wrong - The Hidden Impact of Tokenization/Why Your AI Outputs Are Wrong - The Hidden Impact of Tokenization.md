---
Publish Date: 05/20/2025
---
You didn't write a bad prompt. The model just read it wrong.

![Tokenization](tokenization.webp)

## Key Takeaways

- The fundamental way these models "understand" text isn't through whole words, as humans do. Instead, they interpret sequences of subword units drawn from a finite vocabulary. This mismatch between our expectations and reality is where many issues originate—from hallucinations to truncated outputs.
- Not all AI models see your text the same way. GPT-4o (BPE), Claude (SentencePiece), and Mistral (Tekken) each process prompts through different tokenization lenses. These differences affect not just accuracy but also cost and efficiency.
- A deeper understanding of how a model's tokenizer operates can be a key differentiator in achieving more accurate, efficient results. Whether you're fine-tuning models or designing prompts, knowing the tokenization mechanics gives you an edge that most users lack.

## The Mystery of Broken Outputs

We've all been there. A carefully crafted prompt—clear, concise, complete—yet the AI spits back something that feels garbled, irrelevant, or weirdly truncated.

This isn't necessarily a failure of prompt engineering, though that's what most people initially assume. What's really happening, more often than not, is a fundamental disconnect in how we think models process text versus what's actually happening under the hood.

So, what's going on? In a word: tokenization.

Tokenization is the invisible process that converts carefully written text into discrete subword units that models can process. These units, called tokens, form the foundation of every LLM interaction—and they're frequently the hidden culprit behind those puzzling outputs that make you question your sanity.

## What Is Tokenization, Really?

Language models don't process text word-by-word like we might expect. Instead, they break text into smaller fragments called tokens, which can be full words, parts of words, or even single characters.

It's a bit like taking a beautiful painting and slicing it into puzzle pieces of varying sizes before trying to understand the image. Sometimes those pieces align perfectly with what we'd consider meaningful units, but often they don't.

For example:
- "Apple" = 1 token
- "Unbelievable" = 3 tokens ("Un", "believ", "able")
- "San Francisco" = 2–3 tokens depending on the tokenizer

The research shows that different tokenization approaches can significantly affect real-world results in various ways.

## BPE (Byte Pair Encoding)

OpenAI models rely on BPE, which starts with individual characters and gradually merges frequent pairs to create new subword units. It's deterministic and builds compact vocabularies. BPE tends to work well with English text and programming languages, but can struggle with rare words or specialized terminology.

## SentencePiece

Claude and earlier LLaMA models use SentencePiece, which treats spaces as special symbols. When running in Unigram mode, it selects token sequences probabilistically. This approach tends to be more forgiving with multilingual text and misspellings—a distinction that can make or break international applications.

## Vocabulary Size Matters

Tokenizers are constrained by their vocabulary size—GPT-4's cl100k has about 100,000 tokens, while Mistral's Tekken tokenizer supports roughly 130,000. It's worth noting that larger vocabularies generally mean fewer tokens per sentence, but require more memory. These trade-offs shape how models process information at a fundamental level.

## Why Token Limits Matter

Every model has a context window defined by a maximum token count that includes both input and the model's output. Exceed that limit and something has to give—either the model silently truncates input (usually from the beginning, where critical instructions might live) or it cuts off mid-sentence when generating its response.

The current landscape looks something like this:
- GPT-4o: 128k tokens
- Claude 3 Opus: 200k tokens (though it typically uses 20–30% more tokens than OpenAI)
- Mistral 7B (Tekken): 32k tokens

This can lead to serious problems in real-world applications. RAG systems might start hallucinating because documents are being silently truncated. Users get confident, completely wrong answers because the relevant context is invisibly missing. And troubleshooting these issues is particularly difficult because there's often no error message—just degraded performance.

So, what does this mean for projects using AI? Simply put, the efficiency of tokenization might be the invisible ceiling on system performance.

## Tokenization Trade-offs to Consider

There are important patterns in tokenization performance that aren't widely discussed:

| Strategy | Pros | Cons |
|---|---|---|
| BPE | Fast, compact, deterministic; ideal for code & English | Poor handling of rare words and misspellings |
| SentencePiece (Unigram) | Flexible, multilingual-friendly, handles noisy text | Uses more tokens; probabilistic decoding can vary |
| Hybrid (Tekken) | High compression across languages; improved consistency | Still in early adoption; requires tooling updates |

The differences aren't just academic. Multilingual systems often perform better with SentencePiece, especially with non-Latin scripts. For code generation, BPE tends to deliver more consistent results.

These differences become particularly apparent when dealing with edge cases—specialized vocabulary, code mixed with natural language, or texts with unusual formatting. In those scenarios, the tokenization approach can make the difference between success and unpredictable failure.

## Efficiency Matters—For Your Wallet and Results

Consider the token efficiency for a 1,000-word technical document:
- GPT-4o: ~750 tokens
- Claude 3: ~950–1,050 tokens
- Mistral (Tekken): ~800 tokens

This has real implications for both cost (if you're paying per token) and how much content you can pack into a given context window.

## Analyzing Tokens

When building LLM applications, these tools can help debug tokenization issues:

```python
# OpenAI tiktoken
import tiktoken
enc = tiktoken.encoding_for_model("gpt-4")
tokens = enc.encode("Your text here")
print(len(tokens), tokens)
print(enc.decode(tokens))

# Hugging Face
from transformers import AutoTokenizer
model = "mistralai/Mistral-7B-Instruct-v0.1"
tokenizer = AutoTokenizer.from_pretrained(model)
tokens = tokenizer("Your text here", return_tensors='pt')
print(len(tokens['input_ids'][0]))
print(tokenizer.convert_ids_to_tokens(tokens['input_ids'][0]))
```

## Common Tokenization Pitfalls

Several tokenization issues appear regularly in AI systems:

- **Truncation** – When prompt plus expected output exceeds the limit, leading to mysterious context loss. Critical data points can be silently dropped because they exceed the token limit by just a small percentage.
- **Lost context** – The beginning of prompts can get dropped, which is particularly problematic when that's where the most important instructions live. Systems may appear to "forget" their core instructions when handling complex inputs.
- **Hallucinations** – Split tokens can derail meaning in unexpected ways. This is particularly problematic with domain-specific terminology, where important concepts might be fractured across multiple tokens, losing their semantic coherence.
- **Formatting breakdowns** – Markdown, code blocks, or symbols can split in ways that fundamentally alter how the model interprets them. Code generation can fail when certain constructs are tokenized in ways that break their syntactic meaning.

The field is still evolving, of course. As tokenization strategies improve, some of these issues may become less prominent. But for now, they remain common stumbling blocks that can transform an otherwise well-designed system into an unpredictable one.

## The Impact on Embeddings

Tokenization plays a crucial role in how models create and use embeddings. When meaningful words are fragmented into multiple tokens:
- The embedding loses semantic clarity
- Search becomes noisier
- Subword embeddings may capture morphemes, but lose higher-order meaning

Well-designed tokenizers preserve meaning while compressing space—a balancing act that can make or break retrieval systems.

## When Custom Tokenizers Make Sense

Custom tokenizers are particularly useful when:
- Working in specialized domains with unique vocabulary (medical, legal)
- Fine-tuning models on code or multilingual data
- Optimizing for performance with fewer tokens

However, the tokenizer must match pretraining. A mismatch leads to broken embeddings or misaligned outputs—a mistake that can require extensive debugging.

## Real-World Tokenization Problems

Some common issues that can be solved through better tokenization understanding:
- RAG systems failing silently when token inflation causes document truncation
- Poor embedding quality for numeric queries due to digit splitting
- Multilingual chatbots dropping parts of messages due to inefficient encoding

## What's Next in Tokenization

The field is evolving quickly. Emerging approaches include:
- **ByT5, Canine**: Skip subword tokenization entirely, working at byte or character level
- **Dynamic Tokenizers**: Adapting to input structure on-the-fly
- **Hierarchical Encoders**: Combining subword with sentence or paragraph-level embeddings

Each approach offers better generalization but demands more computational resources—a trade-off that shapes system design.

## Final Thoughts

When AI gives weird outputs, the problem often isn't your prompt—it's how the model perceives your words through the lens of its tokenizer.

Understanding tokenization isn't just for ML engineers. It's essential knowledge for anyone building with AI, from prompt engineers to product managers. Master this hidden layer between human language and machine understanding, and you'll unlock better performance, tighter prompts, cheaper API calls, and more reliable systems.

What this boils down to is simple: in the world of AI, the medium is the message. How words are tokenized shapes how they're understood, processed, and responded to. And that makes tokenization not just a technical detail, but a fundamental aspect of AI communication.
