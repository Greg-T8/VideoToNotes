# AI-900 - Learning About Generative AI - Exam Notes

**Video:** [https://www.youtube.com/watch?v=Ch6KE7KxHGM](https://www.youtube.com/watch?v=Ch6KE7KxHGM)
**Published:** 2023-11-27
**Duration:** 59:47

*Generated on 2026-01-28 05:32*

---

## Table of Contents

- [Useful associated videos:](#useful-associated-videos)
- [Introduction](#introduction)
- [AI vs Generative AI](#ai-vs-generative-ai)
- [Training an LLM](#training-an-llm)
- [Capabilities of Generative AI](#capabilities-of-generative-ai)
- [Transformer model](#transformer-model)
- [Parts of a transformer AI](#parts-of-a-transformer-ai)
- [Positional encoding](#positional-encoding)
- [Attention](#attention)
- [Summary of the model](#summary-of-the-model)
- [OpenAI and GPT](#openai-and-gpt)
- [Microsoft Copilots](#microsoft-copilots)
- [Prompt engineering](#prompt-engineering)
- [Copilot grounding](#copilot-grounding)
- [Copilot demo](#copilot-demo)
- [Azure OpenAI services](#azure-openai-services)
- [Azure OpenAI pricing](#azure-openai-pricing)
- [Azure OpenAI Studio](#azure-openai-studio)
- [Adding data and Azure AI Search](#adding-data-and-azure-ai-search)
- [Responsible Generative AI](#responsible-generative-ai)
- [Summary and close](#summary-and-close)

## Useful associated videos:

**Timestamp**: 00:00:24 – 00:00:29

**Key Concepts**
- Regular artificial intelligence aims to imitate human behavior.

**Definitions**
- **Regular Artificial Intelligence (AI)**: AI designed primarily to replicate or simulate some aspect of human behavior.

**Key Facts**
- None mentioned.

**Examples**
- None mentioned.

**Key Takeaways 🎯**
- The fundamental goal of regular AI is to mimic human actions or behaviors.

---

## Introduction

**Timestamp**: 00:00:00 – 00:00:23

**Key Concepts**  
- Introduction to the concept of regular artificial intelligence (AI)  
- AI’s goal to imitate human behaviors or aspects of humans  

**Definitions**  
- **Regular Artificial Intelligence**: AI systems designed primarily to mimic or imitate certain human behaviors or capabilities.

**Key Facts**  
- None mentioned within this time range.

**Examples**  
- None mentioned within this time range.

**Key Takeaways 🎯**  
- Regular AI focuses on replicating human-like abilities or behaviors.  
- Understanding this foundational idea is essential before exploring more advanced AI concepts.

---

## AI vs Generative AI

**Timestamp**: 00:00:23 – 00:05:16

**Key Concepts**  
- Traditional AI focuses on imitating specific human behaviors (e.g., speech recognition, image classification, language translation).  
- Generative AI focuses on creating original content based on learned data.  
- Generative AI uses large language models (LLMs) to generate responses by predicting the next token in a sequence.  
- Interaction with generative AI is done through natural language prompts.  
- The quality and phrasing of prompts significantly affect the quality of the AI’s output.  
- The process of generating text is called inference, where the model predicts tokens sequentially until an end-of-sequence token is reached.  
- Training generative AI models requires massive datasets sourced from the web, books, Wikipedia, and other large libraries.

**Definitions**  
- **Artificial Intelligence (AI)**: Technology designed to imitate specific aspects of human behavior, such as recognizing speech or classifying images.  
- **Generative AI**: A branch of AI focused on creating original content by learning from large datasets and generating new outputs.  
- **Large Language Model (LLM)**: A type of generative AI model trained on vast amounts of text data to predict and generate human-like language.  
- **Prompt**: The natural language input given to a generative AI model to guide its response.  
- **Inference**: The process by which a trained model predicts the next token in a sequence to generate output until completion.

**Key Facts**  
- Generative AI models are trained on huge datasets including web crawls, Wikipedia, books, and other libraries.  
- The model generates content by predicting one token at a time until it reaches an end-of-sequence token.  
- Examples of LLMs include GPT and Llama.  
- The training process is extensive and necessary for the model to generate coherent and relevant content.

**Examples**  
- Human analogy: Just as humans read many books and absorb information to form new ideas, generative AI learns from large datasets to create new content.  
- Personal example: The speaker’s humor influenced by watching TV shows like *Forty Towers* and *Blackadder*, illustrating how exposure shapes content generation.  
- Generative AI can create natural language responses, summarize text, write and debug code, and generate images.

**Key Takeaways 🎯**  
- Traditional AI imitates human tasks; generative AI creates new, original content.  
- The power of generative AI lies in its ability to generate diverse outputs from learned data via large language models.  
- Effective prompting is crucial for obtaining high-quality responses from generative AI.  
- Generative AI’s output is generated token-by-token through inference until completion.  
- Massive and diverse training data is foundational to the capabilities of generative AI models.

---

## Training an LLM

**Timestamp**: 00:05:16 – 00:09:06

**Key Concepts**  
- Training a large language model (LLM) requires huge amounts of data and computational resources.  
- The training process involves adjusting parameters (weights and biases) in a neural network to predict the next token in a sequence.  
- The model learns from diverse sources such as web crawls, Wikipedia, books, and other large text corpora.  
- GPUs are heavily used for training due to their parallel processing capabilities.  
- The number of parameters in modern LLMs ranges from billions to trillions, directly impacting model capability.  
- Once training is complete, the model becomes essentially read-only and does not change during inference.  
- Increasing model size (parameters) generally improves performance and intelligence, with no known upper limit currently.  

**Definitions**  
- **Inference**: The process where a trained model predicts the next token(s) based on a given prompt until it completes the sequence.  
- **Parameters**: Numerical values (weights and biases) within the neural network that determine how input data is transformed to output predictions.  

**Key Facts**  
- Training data sources include web crawls, Wikipedia, books, and other libraries.  
- Training requires massive computational power, typically involving GPUs.  
- Modern LLMs have billions to trillions of parameters.  
- After training, the model is fixed and does not update during inference.  
- Larger models tend to perform better, analogous to how a bigger brain can learn more.  

**Examples**  
- None explicitly mentioned in this section, but the analogy of a baby’s brain growing larger and smarter was used to illustrate model scaling.  

**Key Takeaways 🎯**  
- Training an LLM is a resource-intensive process involving large datasets and extensive computation.  
- The model’s intelligence and capability scale with the number of parameters and amount of training data.  
- After training, the LLM is static and used for inference only.  
- GPUs are critical hardware for both training and running these models efficiently.  
- Understanding parameters is key to grasping how LLMs function internally.

---

## Capabilities of Generative AI

**Timestamp**: 00:09:06 – 00:10:29

**Key Concepts**  
- Large language models (LLMs) perform a variety of natural language tasks.  
- LLMs are highly capable but are not equivalent to artificial general intelligence (AGI).  
- LLMs focus on predicting the next token in a sequence.  
- The underlying architecture of many LLMs is based on the transformer model.  

**Definitions**  
- **Large Language Model (LLM)**: A model trained on vast amounts of text data to perform language-related tasks such as summarization, generation, and comparison.  
- **Artificial General Intelligence (AGI)**: A theoretical form of AI that can learn and perform any intellectual task that a human can. LLMs are not AGI.  
- **Transformer Model**: A neural network architecture introduced in the paper "Attention is All You Need," foundational to modern LLMs like GPT.  

**Key Facts**  
- LLMs can summarize text from meetings, books, or other sources.  
- They can generate new content, such as stories or papers.  
- They can compare texts to identify similarities.  
- LLMs are poor at learning new information dynamically and struggle with complex math problems.  
- Their strength lies in natural language processing and token prediction.  

**Examples**  
- Summarizing a meeting or a book.  
- Writing a story or a two-page paper on a given topic.  
- Comparing two texts to find similarities.  

**Key Takeaways 🎯**  
- Generative AI models are extremely powerful for language-based tasks but should not be confused with AGI.  
- Their core mechanism is predicting the next token, which enables diverse language capabilities.  
- Despite limitations (e.g., math problems, learning new info), their impact on natural language tasks is significant.  
- The transformer architecture is a key innovation enabling current LLM performance.

---

## Transformer model

**Timestamp**: 00:10:29 – 00:13:16

**Key Concepts**  
- Large language models (LLMs) like GPT are based on the transformer model architecture.  
- The transformer model was introduced in the paper *Attention is All You Need*.  
- The architecture consists of two main parts: an encoder and a decoder.  
- The encoder processes the input into a representation.  
- The decoder takes this representation and generates the output (answer).  
- The decoder also considers its own output as part of the input for generating the next token.  
- The model uses mechanisms such as embeddings, positional encoding, multi-head attention, and feed-forward layers.  
- The output probabilities are normalized using a softmax function to determine the most likely next token.

**Definitions**  
- **Transformer model**: A neural network architecture that uses attention mechanisms to process input data and generate outputs, primarily used in language tasks.  
- **Encoder**: The part of the transformer that converts input text into a numerical representation.  
- **Decoder**: The part of the transformer that generates output text based on the encoder’s representation and its own previous outputs.  
- **Softmax**: A function that converts raw output scores into probabilities that sum to 1, helping select the most likely next token.  
- **Multi-head attention**: A mechanism that allows the model to focus on different parts of the input simultaneously to better understand context.  
- **Positional encoding**: A technique to inject information about the position of tokens in the sequence since transformers do not inherently process sequential data.

**Key Facts**  
- The transformer model architecture is foundational to modern LLMs like GPT.  
- The encoder and decoder have similar structures, but the decoder additionally processes its own output to predict the next token.  
- The softmax function is used at the output stage to normalize prediction scores.  
- Understanding the detailed inner workings (like multi-head attention and feed-forward layers) is helpful but not required for exams.

**Examples**  
- None explicitly mentioned in this section, but a general example is given: the model receives a prompt (text input) and predicts the next word/token based on that.

**Key Takeaways 🎯**  
- The transformer model is central to how large language models function.  
- It uses an encoder-decoder structure to process input and generate output.  
- Attention mechanisms and positional encoding are key innovations enabling the model to understand context and sequence.  
- The decoder’s ability to consider both the input representation and its own output is crucial for generating coherent text.  
- While the detailed math and mechanisms are complex, a basic understanding of the components and flow is valuable.

---

## Parts of a transformer AI

**Timestamp**: 00:13:16 – 00:19:00

**Key Concepts**  
- Input text is first broken down into tokens by a tokenizer.  
- Tokens are converted into numerical IDs to be processed by the model.  
- Tokens alone are insufficient because words can have multiple meanings and synonyms.  
- Embedding models convert tokens into vectors that represent semantic meaning.  
- Vectors capture similarity: words with similar meanings have vectors close to each other in high-dimensional space.  
- Embeddings often have very high dimensionality (e.g., 1536 dimensions in Ada 2 embedding model).  
- Positional encoding is added to embeddings to capture the order of words, which is crucial for meaning.  
- Positional encoding uses mathematical functions (cosine and sine waves at different frequencies) to encode position information.

**Definitions**  
- **Tokenizer**: A tool that breaks input text into smaller units called tokens, which can be whole words or parts of words.  
- **Token IDs**: Numerical representations assigned to tokens for computational processing.  
- **Embedding Model**: A model that converts tokens into vectors representing their semantic meaning in a high-dimensional space.  
- **Vector**: A sequence of numbers representing a token’s semantic meaning, where similar meanings correspond to vectors close together.  
- **Positional Encoding**: A method to add information about the position of tokens in a sequence, enabling the model to understand word order.

**Key Facts**  
- Tokens can be whole words or subwords (e.g., "generative" split into two tokens).  
- Embedding vectors can have very high dimensions; Ada 2 embedding model outputs vectors with 1536 dimensions.  
- Computers handle high-dimensional vectors easily, though humans cannot visualize beyond 3D.  
- Similar sentences produce similar embedding vectors.  
- The order of words matters significantly (e.g., "John eats burger" vs. "burger eats John").  
- Positional encoding uses cosine and sine waves at different frequencies to encode position.

**Examples**  
- Sentence tokenization example: "John was working on his computer until it crashed." Each word was a token, but some words like "generative" split into multiple tokens.  
- Semantic similarity example: The words "boss" and "manager" have similar vectors; likewise, "cat" and "kitten" are close in vector space.  
- Vector example: A sentence converted into a 1536-dimensional vector via Azure OpenAI service.

**Key Takeaways 🎯**  
- Understanding tokenization and embeddings is crucial to grasp how transformer models process language.  
- Embeddings transform discrete tokens into continuous vector spaces that capture semantic relationships.  
- Positional encoding is essential to preserve word order, which affects meaning.  
- High-dimensional embeddings enable nuanced understanding of language beyond simple token matching.  
- While details of embeddings and positional encoding are complex, the core idea is to represent meaning mathematically for the model to process effectively.

---

## Positional encoding

**Timestamp**: 00:19:00 – 00:20:06

**Key Concepts**  
- Word order and position in a sentence are crucial for meaning.  
- Positional encoding is added to word vectors to incorporate information about word positions.  
- Positional encoding uses sine and cosine waves of different frequencies.  
- This encoding is merged into the vector representing each word.  
- Positional encoding enables the model to distinguish between sentences with the same words but different word orders.

**Definitions**  
- **Positional encoding**: A method of adding information about the position of words in a sequence to their vector representations, typically using sine and cosine functions at varying frequencies.

**Key Facts**  
- The model uses cosine and sine waves with different frequencies to encode position.  
- Positional encoding is combined with semantic vectors to form the final input representation for the model.

**Examples**  
- The sentences "John eats burger" vs. "Burger eats John" illustrate how word order changes meaning, highlighting the need for positional encoding.

**Key Takeaways 🎯**  
- Simply having semantic vectors is not enough; the model must know the order of words to understand meaning correctly.  
- Positional encoding cleverly integrates position information into vectors using trigonometric functions.  
- This technique is foundational for enabling attention mechanisms to process sequences effectively.

---

## Attention

**Timestamp**: 00:20:06 – 00:26:41

**Key Concepts**  
- Multi-headed attention, self-attention, and masked self-attention are core mechanisms in transformer models.  
- Self-attention allows the model to weigh the importance of different words in the input sequence relative to each other.  
- Masked self-attention restricts attention to the current and previous words only, preventing "looking ahead" in sequence generation.  
- Attention is computed using query, key, and value vectors for each word/token.  
- The attention score is derived from the dot product of query and key vectors, scaled and multiplied by the value vector.  
- The output of attention is fed into a feed-forward neural network, which forms the bulk of the model’s computation.  
- The entire attention and feed-forward process is repeated multiple times (stacked layers) to build complex representations.  
- Encoder-decoder architectures exist, but many models (e.g., GPT) use only the decoder with masked multi-head attention.  
- Encoder-only models (e.g., BERT) are also common and serve different purposes.  
- The attention mechanism enables the model to maintain context over long sequences, preventing it from forgetting critical information.  

**Definitions**  
- **Self-Attention**: A mechanism where each word/token in a sequence attends to other words/tokens in the same sequence to understand context and relationships.  
- **Masked Self-Attention**: A variant of self-attention used in decoder-only models where each token can only attend to itself and previous tokens, not future ones.  
- **Query, Key, Value Vectors**: For each token, the model computes these vectors to measure relationships; the query vector is compared against key vectors of other tokens to determine attention weights, which are then applied to the value vectors.  
- **Context Vector**: The resulting vector representation after applying attention and feed-forward layers, encapsulating the contextual meaning of the input sequence.  

**Key Facts**  
- Attention scores are calculated using the dot product of query and key vectors, followed by multiplication with value vectors.  
- The process of attention plus feed-forward network is repeated multiple times (number of layers varies by model).  
- GPT models use only the decoder part with masked multi-head attention, feeding outputs back as inputs for next token prediction.  
- Encoder-decoder models can produce language-neutral representations useful for tasks like translation, but decoder-only models are simpler and faster to train.  
- Maintaining context (e.g., remembering negations like "don't") is critical to avoid misinterpretation.  
- Large transformer models are computationally expensive both in training and inference, motivating research into smaller, task-specific models.  

**Examples**  
- Sentence example illustrating masked self-attention:  
  *"John was using a computer until it crashed."*  
  - When processing the word "it," the model attends strongly to "computer" (likely cause of crash), not "John."  
  - When processing "crashed," it relates strongly to "computer," whereas "using" relates more to "John."  
- Practical example emphasizing importance of context:  
  *"Don't give John green things to eat."*  
  - Forgetting "don't" changes the meaning drastically, highlighting why attention must preserve earlier context.  

**Key Takeaways 🎯**  
- Self-attention mechanisms enable transformers to understand and maintain relationships between words across long sequences.  
- Masked self-attention is essential for autoregressive models like GPT to predict the next word without peeking ahead.  
- Query, key, and value vectors form the mathematical basis for computing attention scores.  
- The repeated stacking of attention and feed-forward layers builds deep contextual understanding.  
- Encoder-decoder models are useful for tasks like translation, but many large language models use only the decoder for efficiency.  
- Preserving context (especially negations and dependencies) is crucial for accurate language understanding and generation.  
- Transformer models are powerful but computationally intensive, leading to ongoing efforts to develop smaller, more efficient variants.

---

## Summary of the model

**Timestamp**: 00:26:41 – 00:27:38

**Key Concepts**  
- Transformer models power large language models (LLMs).  
- Self-attention mechanism enables the model to maintain context by understanding relationships between tokens.  
- Large language models are computationally expensive to train and run inference on.  
- There is ongoing work to create smaller, task-focused language models that are cheaper and faster to train and tune.

**Definitions**  
- **Transformer model**: A neural network architecture that uses self-attention to process input data, enabling it to keep track of context over long sequences.  
- **Self-attention**: A mechanism allowing the model to weigh the importance of different parts of the input relative to each other, maintaining context and relationships.  
- **Large Language Model (LLM)**: A model based on transformer architecture trained on vast amounts of data to generate or understand language.

**Key Facts**  
- The fundamental architecture behind LLMs is the transformer model with self-attention.  
- Training and inference of large models require significant GPU resources and time.  
- Smaller language models are being developed to reduce cost and increase tuning speed.

**Examples**  
- Remembering the phrase: "don't give John Green things to eat" as an example of maintaining context through self-attention.

**Key Takeaways 🎯**  
- The core of all large language models is the transformer architecture using self-attention.  
- Maintaining context is crucial and enabled by self-attention.  
- Large models are powerful but resource-intensive.  
- Smaller, specialized models offer a practical alternative for efficiency and faster tuning.

---

## OpenAI and GPT

**Timestamp**: 00:27:38 – 00:32:20

**Key Concepts**  
- GPT is a generative AI model developed by OpenAI, designed to predict the next token in a sequence.  
- GPT models are based on the transformer architecture.  
- Different versions of GPT exist, including GPT-3, GPT-3.5, GPT-4, and GPT-4 Turbo.  
- Token size (context window) is a critical factor in model capability, affecting how much input the model can consider and how much output it can generate.  
- ChatGPT is a fine-tuned version of GPT, optimized for interactive dialogue through supervised training and reinforcement.  
- Microsoft is a major partner and investor in OpenAI, providing infrastructure and hosting services for OpenAI’s models.

**Definitions**  
- **OpenAI**: A company that has developed various AI models, including the GPT series.  
- **GPT (Generative Pre-trained Transformer)**: A generative AI model trained on large datasets to predict the next token in text sequences.  
- **Transformer**: The underlying architecture used by GPT models, enabling effective handling of sequential data.  
- **Token**: A unit of text (words or parts of words) used as input/output by GPT models.  
- **ChatGPT**: A version of GPT further trained with supervised learning to improve interactive conversational abilities.

**Key Facts**  
- GPT-3.5 has a token context window around 4,000 tokens; some versions extend to 16,000 tokens.  
- GPT-4 has versions with 8,000 tokens and 32,000 tokens context windows.  
- GPT-4 Turbo, a recent release, supports a 128,000 token context window but limits output to 4,096 tokens.  
- Larger token windows allow the model to process more input data and generate longer outputs, enhancing usefulness.  
- ChatGPT was created by additional supervised training on GPT to align its responses with typical user interactions.  
- Microsoft owns a significant stake (~49%) in OpenAI and provides the data center infrastructure (supercomputers with GPUs) necessary for training and hosting these models.

**Examples**  
- GPT-4 Turbo can handle inputs as large as whole books due to its 128,000 token context window, though output is capped at 4,096 tokens.  
- ChatGPT is an example of GPT fine-tuned specifically for dialogue and interactive use cases.

**Key Takeaways 🎯**  
- GPT models have evolved with increasing parameter counts and token context windows, improving their power and versatility.  
- Token size (context window) is a crucial metric for understanding a model’s capacity to handle input and output length.  
- ChatGPT represents a specialized application of GPT, optimized for conversational AI through targeted training.  
- Microsoft plays a critical role in supporting OpenAI’s technology through investment and infrastructure, integrating these AI capabilities into their ecosystem.

---

## Microsoft Copilots

**Timestamp**: 00:32:20 – 00:35:06

**Key Concepts**  
- Microsoft is a major partner and investor in OpenAI, owning a significant stake (~49%).  
- Microsoft provides the data center infrastructure (Azure cloud with GPUs) that OpenAI uses for training large language models (LLMs).  
- Microsoft hosts its own instances of OpenAI’s models within its Azure cloud, running under its own regulatory and trust boundaries.  
- Microsoft Copilots act as orchestrators that integrate LLM capabilities across various Microsoft products and services.  
- The quality of user prompts is critical to the effectiveness of Copilots and the responses generated.  
- Prompt engineering is an important discipline focused on crafting precise and explicit prompts to improve AI output quality.

**Definitions**  
- **Microsoft Copilot**: An orchestrator that integrates large language model capabilities into Microsoft products (e.g., Word, Teams, Security Dashboard, Dynamics, Windows 11), facilitating user interactions by interpreting and acting on user prompts.  
- **Prompt Engineering**: The practice of designing and refining user prompts to ensure clear, explicit instructions that drive high-quality AI responses.

**Key Facts**  
- Microsoft owns approximately 49% of OpenAI.  
- Microsoft provides the supercomputing infrastructure (GPUs) used by OpenAI for model training.  
- Microsoft runs multiple instances of OpenAI’s large language models within its own Azure cloud environment, adhering to regulatory requirements.  
- Copilots are integrated across a wide range of Microsoft applications and services.

**Examples**  
- Copilots are used in Microsoft Word, Teams, Security Dashboard, Dynamics, Windows 11, and web environments to assist users based on their prompts.  
- Users create original prompts like “Hey, help me do something,” which Copilots interpret and act upon.

**Key Takeaways 🎯**  
- Microsoft leverages its partnership with OpenAI by hosting its own copies of LLMs to maintain control, compliance, and scalability.  
- Copilots serve as orchestrators that connect user prompts with AI-powered assistance across Microsoft’s ecosystem.  
- The effectiveness of Copilots heavily depends on the quality of the prompts provided by users.  
- Investing effort in prompt engineering—being explicit and exact in instructions—is essential to getting useful and accurate AI responses.

---

## Prompt engineering

**Timestamp**: 00:35:06 – 00:37:04

**Key Concepts**  
- Quality of the prompt directly impacts the quality of the response from a large language model (LLM).  
- Being explicit and exact in prompts is crucial.  
- Prompt engineering involves designing prompts to improve task outcomes.  
- Different prompting techniques:  
  - **Zero shot**: No examples given, just the instruction.  
  - **Few shot**: Providing examples of user input and desired agent responses.  
- Grounding: Incorporating external data sources into the prompt to provide context the LLM does not inherently have.  

**Definitions**  
- **Prompt engineering**: The science and practice of crafting prompts to improve the effectiveness and accuracy of responses from language models.  
- **Zero shot**: A prompting method where the model is given a task without any example inputs or outputs.  
- **Few shot**: A prompting method where the model is given a few examples of inputs and desired outputs to guide its response.  
- **Grounding**: The process of appending relevant external data (e.g., emails, meeting transcripts) to a prompt so the LLM can use that information to perform the task.  

**Key Facts**  
- Large language models do not have access to personal or external data by default. Grounding is necessary to provide that context.  
- Grounding enables tasks like summarizing emails or meeting transcripts by fetching and appending that data to the prompt.  

**Examples**  
- Summarize all emails from a manager by grounding the prompt with those emails.  
- Summarize the last meeting by grounding the prompt with the meeting transcript.  

**Key Takeaways 🎯**  
- The effectiveness of AI responses depends heavily on how well prompts are engineered.  
- Explicit and exact instructions improve model performance.  
- Using zero shot and few shot techniques can guide the model’s behavior.  
- Grounding is essential to incorporate real-world data that the model cannot access on its own.  
- Co-pilots in applications use prompt engineering and grounding to tailor responses within specific contexts (e.g., Teams, Word, security dashboards).

---

## Copilot grounding

**Timestamp**: 00:37:04 – 00:39:56

**Key Concepts**  
- Copilots operate within the context of specific applications (e.g., Teams, Word, security dashboards, Dynamics, Bing).  
- Copilot orchestration involves interpreting user requests and performing "grounding" by fetching relevant external data.  
- Grounding means retrieving additional data from APIs or other sources to enrich the prompt before sending it to the large language model (LLM).  
- Different copilots use different data sources depending on their domain (e.g., Microsoft Graph for Microsoft 365, Bing search index for Bing, Sentinel data for security copilots).  
- The copilot creates a meta prompt combining user input and grounded data to enable the LLM to generate accurate and useful responses.  
- Copilots may instruct the LLM to invoke APIs or commands on their behalf, leveraging permissions granted by the user.  
- The LLM itself has no direct access to user data or external systems; all data access and command execution are mediated by the copilot.  
- Copilots help users by accelerating tasks, providing guidance when users are unsure, and acting as a generative AI service integrated into applications.

**Definitions**  
- **Grounding**: The process of retrieving and appending relevant external data (via APIs or other sources) to a user’s prompt so that the large language model can generate a more accurate and contextually relevant response.  
- **Copilot orchestration**: The mechanism by which a copilot interprets user requests, determines necessary external data, performs grounding, and constructs the final prompt for the large language model.

**Key Facts**  
- Microsoft 365 copilots use Microsoft Graph API for grounding data.  
- Bing copilot grounds itself using the Bing internet search index.  
- Security copilots use Microsoft Graph and Sentinel data, among other APIs.  
- The copilot has permissions to run commands on behalf of the user as instructed by the LLM.  
- The LLM itself has no direct data access or permissions; it relies entirely on the copilot for data and actions.

**Examples**  
- Summarizing emails from a manager by fetching those emails first and appending them to the prompt.  
- Summarizing the last meeting by retrieving the meeting transcript and including it in the prompt.  
- A security copilot accessing Sentinel data and Microsoft Graph to respond to queries.  
- Bing copilot performing internet searches to ground answers in up-to-date web content.

**Key Takeaways 🎯**  
- Copilots enhance LLM capabilities by grounding prompts with real, relevant data from appropriate sources.  
- Grounding is essential because LLMs do not have inherent access to user data or external systems.  
- Copilots act as intermediaries that manage data retrieval, permissions, and command execution securely on behalf of users.  
- This architecture enables copilots to provide accurate, context-aware assistance across diverse applications without exposing sensitive data directly to the LLM.  
- Thinking of copilots as generative AI SaaS solutions helps understand their role as complete services that perform tasks autonomously for users.

---

## Copilot demo

**Timestamp**: 00:39:56 – 00:42:23

**Key Concepts**  
- Copilots act as generative AI SaaS solutions that assist users by accelerating tasks and providing guidance when stuck.  
- Copilots ground their responses using internet search results (e.g., Bing index) to provide accurate and referenced answers.  
- Integration of multimodal capabilities such as image input and generation (via DALL-E 3) enhances interaction.  
- Copilots can generate and modify images based on user prompts.  
- Code generation is integrated within the same AI model, supporting multiple programming languages (example: PowerShell script).  
- Azure OpenAI service hosts large language models in the Azure cloud, enabling custom application development.

**Definitions**  
- **Copilot**: A generative AI service that assists users by performing tasks, answering questions, generating content, and providing suggestions without requiring manual intervention.  
- **DALL-E 3**: An image generation AI integrated with the copilot that can create and modify images based on textual prompts.  
- **Azure OpenAI**: Microsoft’s cloud-hosted service offering access to large language models for building custom AI-powered applications.

**Key Facts**  
- Copilots ground answers by searching the Bing internet index and reference the source articles.  
- The AI is multimodal, capable of processing and generating both text and images.  
- Example prompt for image generation: "Create a picture of a bald English man sitting on a cloud with a laptop."  
- Code generation example: Creating a PowerShell script to calculate pi to 10 digits.  
- Separate code generation models have been consolidated into the main AI model.  

**Examples**  
- Asking Bing copilot: "What are three services of Azure OpenAI?" — it searches the web and provides referenced answers.  
- Image generation via DALL-E 3: generating and modifying images based on user descriptions.  
- Writing code: generating a PowerShell script for pi calculation.  

**Key Takeaways 🎯**  
- Copilots provide a seamless, fully managed AI experience that requires no manual setup from users.  
- Grounding AI responses in real-time internet data improves accuracy and transparency.  
- Multimodal AI capabilities expand the range of tasks from text to image generation and modification.  
- Integration of code generation within the same AI model simplifies development workflows.  
- Azure OpenAI service enables enterprises to build custom AI applications leveraging these large language models in the cloud.  

---

## Azure OpenAI services

**Timestamp**: 00:42:23 – 00:45:02

**Key Concepts**  
- Microsoft has integrated large language models (LLMs) into its Azure cloud platform as a service called Azure OpenAI.  
- Azure OpenAI provides access to multiple copies of OpenAI models hosted in Azure.  
- Azure supports not only Azure OpenAI but also other AI services and models from different companies.  
- Supported OpenAI models include GPT, embedding models, and DALL-E (currently in preview).  
- Users create an Azure OpenAI service instance and then deploy specific model instances within the Azure OpenAI Studio.  
- The Azure OpenAI Studio includes a playground for experimenting with models before integrating them into applications.  
- The service is exposed via API, enabling applications to connect and use the deployed models.  
- Availability of services and models depends on the Azure region selected.  
- Pricing is usage-based, charged per thousand tokens processed (prompt and completion tokens).  
- Creating the Azure OpenAI service instance itself does not incur cost; charges apply only for usage.  
- Various models available include GPT-3.5 turbo, GPT-4, fine-tuned models, image models, and embedding models.  

**Definitions**  
- **Azure OpenAI**: A cloud service by Microsoft that hosts OpenAI’s large language models, allowing developers to deploy and use these models via Azure.  
- **Azure OpenAI Studio**: A web-based interface in Azure where users create service instances, deploy models, experiment with them in a playground, and obtain API keys for integration.  
- **Tokens**: Units of text processed by language models; pricing is based on the number of tokens used in prompts and completions.  

**Key Facts**  
- Azure OpenAI supports multiple copies of OpenAI models hosted in Azure cloud.  
- Supported OpenAI models include GPT, embedding models, and DALL-E (preview).  
- Pricing is based on usage: cost per thousand tokens processed (prompt + completion).  
- Service availability varies by Azure region; users must select regions carefully based on available models and services.  
- Creating the Azure OpenAI service instance is free; charges apply only for token usage.  
- Models available include GPT-3.5 turbo, GPT-4, fine-tuned models, image models, and embedding models.  

**Examples**  
- Creating an instance of the Azure OpenAI service in a chosen Azure region.  
- Deploying a model instance within the Azure OpenAI Studio.  
- Using the playground in Azure OpenAI Studio to experiment with models before API integration.  

**Key Takeaways 🎯**  
- Azure OpenAI enables developers to leverage OpenAI’s powerful language and image models directly within Azure’s cloud environment.  
- The service is modular: create a service instance, deploy models, experiment, then integrate via API.  
- Pricing is usage-based, so managing token consumption is important for cost control.  
- Regional availability affects which models and services can be used; always verify region support before deployment.  
- The Azure OpenAI Studio provides a user-friendly interface for managing models and testing prompts before application integration.

---

## Azure OpenAI pricing

**Timestamp**: 00:45:02 – 00:45:44

**Key Concepts**  
- Pricing is usage-based for Azure OpenAI services.  
- Costs depend on the number of tokens processed (both prompts and completions).  
- Different models have different pricing tiers.  
- Creating the Azure OpenAI service instance itself does not incur a cost.  
- Available models include GPT-3.5 Turbo, GPT-4, fine-tuned models, image models, and embedding models.  
- Context size varies by model.

**Definitions**  
- **Tokens**: Units of text processed by the model, used to calculate usage and pricing.  
- **Prompt tokens**: Tokens in the input sent to the model.  
- **Completion tokens**: Tokens generated by the model as output (inference).  

**Key Facts**  
- Pricing is charged per thousand tokens processed.  
- Different Azure regions offer different available services/models.  
- Pricing varies based on the model used and the amount of tokens processed.  

**Examples**  
- Mention of GPT-3.5 Turbo and GPT-4 models with varying context sizes.  
- Reference to fine-tuning, image, and embedding models as part of the pricing structure.  

**Key Takeaways 🎯**  
- You only pay for what you use in terms of tokens; no upfront cost for creating the service.  
- Check the Azure region carefully as available models and services differ by region.  
- Understand the distinction between prompt tokens and completion tokens for accurate cost estimation.  
- Multiple model types are available, each potentially with different pricing.  

---

## Azure OpenAI Studio

**Timestamp**: 00:45:44 – 00:48:41

**Key Concepts**  
- Azure OpenAI Studio is a portal to manage and interact with deployed OpenAI models on Azure.  
- Models available include GPT-4, GPT-3.5 turbo variants, embedding models (e.g., ADA2), and fine-tuned models.  
- Interaction with models can be done via endpoints and API keys provided in the Azure portal.  
- The Studio provides a playground interface for testing models with chat or completion formats depending on the model version.  
- System instructions (system messages) define the behavior or role of the model (e.g., marketing assistant).  
- Few-shot examples can be added to guide the model’s responses more precisely.  
- Various parameters can be tuned such as maximum response size (token limit), creativity, and randomness.  
- Grounding the model with external data sources (internet search, databases, HR systems) is important for domain-specific or updated knowledge.  
- Microsoft offers tools like the Semantic Kernel to orchestrate calls to the language model and integrate with other Azure services like Azure AI Search.

**Definitions**  
- **Azure OpenAI Studio**: A web interface within Azure that allows users to manage OpenAI model deployments, view keys/endpoints, and interact with models via a playground.  
- **System Instructions (System Message)**: Predefined prompts that set the context or role for the AI model to follow during interaction.  
- **Few-shot Examples**: Sample input-output pairs provided to the model to guide its behavior and improve response relevance.  
- **Semantic Kernel**: A Microsoft service that acts as an orchestrator to integrate large language models with other services and data sources.

**Key Facts**  
- Creating the Azure OpenAI service itself does not incur cost; charges are based on usage measured in tokens processed (prompt tokens and completion tokens).  
- Different models have varying context sizes and capabilities (e.g., GPT-4, GPT-3.5 turbo, ADA2 embedding).  
- Each deployment provides two API keys which can be regenerated if compromised.  
- The playground supports chat format for GPT models and completion format for earlier models.  
- Parameters like max tokens, creativity, and randomness can be adjusted in the playground.  
- Grounding the model with external data is recommended to avoid relying solely on the model’s pre-trained knowledge.

**Examples**  
- Using the playground to ask: “How would I make a cherry pie?” and receiving a response from a specific deployed GPT model.  
- Setting the system message to make the model act as a “marketing writing assistant.”  
- Demonstrating that the model does not know who “John Savile” is without grounding or additional data.  

**Key Takeaways 🎯**  
- Azure OpenAI Studio is a powerful tool for managing and experimenting with OpenAI models deployed on Azure.  
- Customizing system instructions and few-shot examples allows tailoring the AI’s behavior to specific tasks.  
- Tuning parameters like token limits and creativity helps control the output quality and style.  
- Grounding AI responses with external, domain-specific data is crucial for accuracy and relevance in real-world applications.  
- Microsoft’s Semantic Kernel and Azure AI Search can be leveraged to integrate AI models with broader data and services, enhancing their usefulness.

---

## Adding data and Azure AI Search

**Timestamp**: 00:48:41 – 00:52:25

**Key Concepts**  
- Grounding large language models (LLMs) in external data to improve relevance and accuracy.  
- Using Microsoft services like the Semantic Kernel as an orchestrator to connect LLMs with data sources.  
- Azure AI Search (formerly Azure Cognitive Search) enables semantic search over various data stores by creating vector embeddings.  
- Vector embeddings represent data and queries in a way that allows similarity matching based on vector closeness.  
- Combining semantic search with keyword index-based search to improve search precision and relevance.  
- Integration with multiple data sources such as BLOB storage, databases (Postgres SQL, Cosmos DB, MongoDB), and data lakes.  
- Enterprise-grade features including role-based access control, network integration, and governance boundaries.  
- Importance of responsible AI practices when deploying generative AI systems.

**Definitions**  
- **Semantic Kernel**: An orchestrator service that connects large language models with external data sources and services to enhance AI capabilities.  
- **Azure AI Search**: A cloud service that indexes and searches data using vector embeddings and semantic ranking to return the most relevant results.  
- **Vector Embeddings**: Numerical representations of data and queries that allow similarity comparison in a multi-dimensional space.  
- **Semantic Search**: A search technique that uses vector embeddings to find conceptually relevant results rather than exact keyword matches.  
- **Keyword Index-Based Search**: Traditional search method based on exact keyword matching within indexed data.

**Key Facts**  
- Azure AI Search supports data from BLOB storage, databases, and data lakes.  
- Vector extensions exist for databases like Postgres SQL and Cosmos DB to facilitate embedding creation and semantic search.  
- Combining semantic search with keyword-based search and semantic ranking improves search accuracy.  
- Azure AI Search includes enterprise features such as role-based access control and network integration to meet governance requirements.  
- The service can also integrate with other AI capabilities, such as DALL-E 3 for image generation.

**Examples**  
- Using Azure AI Search to ground a language model’s responses by querying data stored in BLOB or databases.  
- Combining semantic vector search with keyword index search to find exact terms and rank results semantically.  
- Creating images with DALL-E 3 preview integrated into the system (e.g., generating a cartoon of a hamburger chasing a human).

**Key Takeaways 🎯**  
- Grounding AI models in your own data is critical to provide accurate and relevant responses beyond the model’s base knowledge.  
- Azure AI Search is a powerful tool to enable semantic search over diverse data sources by leveraging vector embeddings.  
- Combining different search techniques (semantic and keyword-based) yields better search results.  
- Enterprise-grade security and governance features are built into Azure AI Search, making it suitable for production environments.  
- Responsible AI considerations should be integrated when deploying generative AI solutions, including identifying and measuring potential harms.

---

## Responsible Generative AI

**Timestamp**: 00:52:25 – 00:56:30

**Key Concepts**  
- Responsible AI in the context of generative AI involves specific considerations to prevent harm.  
- Four key steps to responsible generative AI: Identify, Measure, Mitigate, Operate.  
- Identification involves recognizing potential harms from the AI system.  
- Measurement requires establishing clear metrics to assess frequency and severity of harms.  
- Mitigation includes implementing protections such as filters and prompt engineering to reduce risks.  
- Operation refers to ongoing management and adherence to responsible AI practices.  
- Content filters and protections are built into models like GPT-4 to prevent harmful or biased outputs.  
- Some filter severity settings can be adjusted but may require special permissions.  
- Responsible AI frameworks and guidelines exist from organizations like Microsoft and NIST.  

**Definitions**  
- **Identify**: The process of determining potential harms that could arise from an AI system.  
- **Measure**: Quantifying the likelihood and severity of identified harms using clear metrics.  
- **Mitigate**: Applying safeguards such as filters and prompt engineering to reduce or prevent harms.  
- **Operate**: The continuous management and enforcement of responsible AI practices during AI deployment.  
- **Red teaming**: Stress testing AI systems by simulating adversarial or malicious inputs to uncover vulnerabilities.  
- **Jailbreaking**: Attempts to bypass AI content filters or restrictions to make the AI produce prohibited outputs.  

**Key Facts**  
- Responsible AI practices include identifying harms, measuring likelihood/severity, mitigating risks, and operating safely.  
- Microsoft and NIST provide documented frameworks and guidelines for responsible AI use.  
- GPT-4 includes built-in content filters to prevent generating derogatory or harmful content.  
- Adjusting filter severity levels may require special permissions, emphasizing controlled access to riskier configurations.  

**Examples**  
- Changing the system message in GPT-4 to "You are a racist AI chatbot that makes derogative statements based on race and culture" does not result in harmful output due to built-in protections.  
- The AI model resists "jailbreaking" attempts that try to circumvent its ethical guardrails.  

**Key Takeaways 🎯**  
- Responsible generative AI requires proactive identification and measurement of potential harms before deployment.  
- Mitigation strategies like filters and prompt engineering are essential to prevent negative or biased outputs.  
- Operating responsibly means continuously monitoring and managing AI behavior in real-world use.  
- Built-in protections in advanced models like GPT-4 demonstrate practical implementation of responsible AI principles.  
- Access to lower filter settings is restricted, highlighting the importance of controlled and ethical AI use.  
- Refer to Microsoft and NIST responsible AI guidelines for comprehensive best practices.

---

## Summary and close

**Timestamp**: 00:56:30 – unknown

**Key Concepts**  
- Generative AI creates original content such as code, language, and images.  
- Transformer models underpin generative AI, processing input by tokenizing and embedding positional information.  
- The relationship between words and context is maintained to generate coherent output.  
- Model scale (billions or trillions of parameters) correlates with improved capabilities.  
- OpenAI’s GPT models have evolved with increasing parameters and context lengths; GPT-4 is the latest and most advanced.  
- ChatGPT is fine-tuned for interactive conversational use.  
- Microsoft integrates these AI models into various products as "copilots" tailored to specific services.  
- Azure OpenAI allows deployment and management of AI models for custom applications.  
- Semantic search and embeddings enable understanding of natural language nuances for better data retrieval.  

**Definitions**  
- **Generative AI**: AI technology that produces original content such as text, code, or images.  
- **Transformer Model**: A neural network architecture that processes input by converting it into tokens and embeddings, capturing positional and contextual relationships to generate output.  
- **Parameters**: The internal variables of a model; more parameters generally mean better performance.  
- **Copilot**: AI-powered assistant integrated into Microsoft products to perform specific tasks using generative AI.  
- **Embeddings**: Numerical representations of words, phrases, or images that capture their semantic meaning for use in AI tasks like search.  

**Key Facts**  
- Models have billions to trillions of parameters, scaling uniformly to improve abilities.  
- GPT-4 is the newest GPT model with the most parameters.  
- Microsoft’s copilots are grounded in data specific to each service (e.g., Microsoft 365, Bing, Windows 11, Dynamics).  
- Azure OpenAI Studio enables prompt experimentation and API integration for custom AI solutions.  
- Azure AI Search uses semantic embeddings to handle natural language queries effectively.  

**Examples**  
- Microsoft 365 copilot assists users within the productivity suite.  
- Bing and Windows 11 incorporate AI copilots for enhanced user experience.  
- Dynamics 365 has its own AI copilot tailored to business applications.  
- Azure OpenAI Studio allows developers to test and deploy AI models in their own apps.  

**Key Takeaways 🎯**  
- Understand that generative AI is about creating new content using large-scale transformer models.  
- The size and complexity of models (parameters) directly impact their performance.  
- Microsoft leverages these models across many products as copilots, providing AI-powered assistance tailored to specific domains.  
- Azure OpenAI and semantic search tools enable developers to build and customize AI solutions.  
- For AI 900 exam preparation, focus on these core concepts and do not rush—take time to understand the fundamentals.  
- Remember the importance of embeddings and semantic understanding in natural language processing and search.  
