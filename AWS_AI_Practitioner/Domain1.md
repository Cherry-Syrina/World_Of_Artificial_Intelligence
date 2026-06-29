# AWS AI Practitioner (AIF-C01)
# Domain 2 - Task Statement 2.1 (Lesson 1)
## Basic Concepts of Generative AI

---

# 📌 What is Generative AI?

Generative AI **Deep Learning ka subset** hai.

Iska main purpose hai **naya (original) content generate karna**, na ki sirf existing data ko classify ya predict karna.

### Generative AI create kar sakta hai:
- 📝 Text
- 🖼️ Images
- 🎵 Audio
- 🎥 Video
- 💻 Code

---

# Traditional AI vs Generative AI

| Traditional AI | Generative AI |
|----------------|---------------|
| Prediction karta hai | New content create karta hai |
| Classification karta hai | Content generation karta hai |
| Existing data analyze karta hai | Learned patterns se naya output banata hai |

Example:

Traditional AI
- Spam Email Detection
- Face Recognition

Generative AI
- Essay likhna
- Image banana
- Code generate karna

---

# How Generative AI Works

Generative AI models pehle bahut saare data se **patterns aur relationships learn** karte hain.

Uske baad wahi knowledge use karke similar but **new content** generate karte hain.

Flow:

Training Data

↓

Learn Patterns

↓

Generate New Content

---

# Foundation Models (FM)

Generative AI ka base hota hai **Foundation Models (FM).**

Features:

- Huge datasets par trained hote hain.
- Multiple tasks perform kar sakte hain.
- Natural language aur images jaise modalities ko samajhte hain.

Example:

- Text Models
- Image Models
- Multimodal Models

---

# Neural Networks

Foundation Models bane hote hain:

- Deep Neural Networks
- Billions of Parameters

Ye neural networks training ke time knowledge learn karte hain.

---

# Parameters

Parameter = Model ki learned memory.

### Rule:

➡️ More Parameters

= More Knowledge

= Better Understanding

= Better Performance

= More Advanced Tasks

Example:

Small Model
→ Few Million Parameters

Large Language Model
→ Billions of Parameters

---

# Fine-Tuning

Foundation Model ko do tarike se use kar sakte hain:

### 1. Directly

General-purpose tasks ke liye.

### 2. Fine-Tuning

Specific business ya domain ke liye extra training dena.

Example:

General LLM

↓

Medical Data

↓

Medical Assistant

---

# Components of a Generative AI Model

Ek model multiple cheezon se milkar banta hai:

- Neural Networks
- Training Data
- System Resources (GPU/TPU)
- Prompts

Ye sab milkar output generate karte hain.

---

# Output Generation

Model input leta hai.

↓

Input ko process karta hai.

↓

Next token ki probability calculate karta hai.

↓

Most likely token choose karta hai.

↓

Sentence complete karta hai.

**Important:**

Model answer "yaad" nahi rakhta.

Wo probability ke basis par next token predict karta hai.

---

# Transformer Architecture

Modern Generative AI ka backbone:

## Transformer Network

Introduced in:

**2017 Research Paper**

**"Attention Is All You Need"**

Most modern LLMs isi architecture par based hain.

Example:

- ChatGPT
- Claude
- Llama
- Amazon Titan

---

# Why Transformers?

Advantages:

- Long context samajhte hain.
- Fast training.
- Parallel processing.
- Better language understanding.

---

# Large Language Model (LLM)

LLM = Large Language Model

Features:

- Internet ke huge text data par pre-trained
- Natural language samajhta hai
- Human-like responses generate karta hai

Tasks:

- Question Answering
- Translation
- Summarization
- Story Writing
- Coding
- Chatbots

---

# Pre-training

LLM pehle huge internet data par train hota hai.

Is process ko kehte hain:

**Pre-training**

Result:

Model ke paas general knowledge aa jati hai.

---

# Fine-Tuning After Pre-training

Pre-training ke baad model ko specific task ke liye dubara train kiya ja sakta hai.

Example:

General LLM

↓

Legal Documents

↓

Legal AI Assistant

---

# Important Exam Concepts

AWS exam ke liye ye terms bahut important hain:

- Prompt
- Completion
- Inference
- Context Window
- Token
- Tokenizer
- Vocabulary
- Prompt Engineering
- Few-shot
- One-shot
- Zero-shot
- In-context Learning

---

# Prompt

User jo instruction deta hai.

Usko kehte hain:

**Prompt**

Example:

```
Write a poem on India.
```

---

# Completion

Model jo response generate karta hai.

Usko kehte hain:

**Completion**

Prompt

↓

Completion

---

# Inference

Training complete hone ke baad

Real users ke prompts ka answer generate karna.

Is process ko kehte hain:

**Inference**

Training ≠ Inference

Training = Learning

Inference = Prediction/Response Generation

---

# Prompt Engineering

Kabhi first response perfect nahi hota.

Prompt ko improve karke better output lena hi:

**Prompt Engineering**

Example:

❌ Bad Prompt

```
Write article.
```

✅ Better Prompt

```
Write a 500-word SEO-friendly article on Cloud Computing with examples.
```

---

# In-Context Learning

Prompt ke andar hi examples provide karna.

Is technique ko bolte hain:

**In-Context Learning**

Isse model ko task samajhne me help milti hai.

---

# Few-shot Learning

Prompt ke andar multiple examples diye jate hain.

Example:

```
Dog → Kutta

Cat → Billi

Bird → ?
```

---

# One-shot Learning

Sirf ek example diya jata hai.

Example:

```
Apple → Seb

Orange → ?
```

---

# Zero-shot Learning

Koi example nahi.

Sirf instruction.

Example:

```
Translate into Hindi:

Good Morning
```

---

# Context Window

Model ek time par jitna text dekh sakta hai.

Usko kehte hain:

**Context Window**

Iske andar:

- Prompt
- Previous conversation
- Examples

sab include hote hain.

---

# Tokens

LLM words ko directly process nahi karta.

Sentence ko small pieces me todta hai.

Ye small pieces kehlate hain:

**Tokens**

Example:

```
I love AWS
```

↓

"I"

↓

"love"

↓

"AWS"

---

# Tokenizer

Tokenizer ka kaam:

Text

↓

Tokens me convert karna.

Without tokenizer model text nahi samajh sakta.

---

# Vocabulary

Model jitne unique tokens jaanta hai.

Us collection ko kehte hain:

**Vocabulary**

Vocabulary jitni achhi hogi,

utni language understanding better hogi.

---

# ML Uses Mathematics

Machine Learning directly text ya images par kaam nahi karta.

Sab kuch numbers me convert hota hai.

Important concepts:

- Statistics
- Probability
- Linear Algebra
- Matrix Multiplication
- Loss Function

Ye sab Deep Learning ki backbone hain.

---

# Inference Configuration Parameters

Inference ke time kuch settings output ko control karti hain.

Ye decide karti hain:

- Creativity
- Randomness
- Response Length
- Writing Style

---

# Exam Tips ⭐

Remember these one-liners:

- AI → Predicts
- Generative AI → Creates
- Prompt → Input
- Completion → Output
- Inference → Response Generation
- Transformer → Backbone of LLMs
- Token → Smallest text unit
- Tokenizer → Converts text into tokens
- Fine-Tuning → Customize a foundation model
- More Parameters → More capability
------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------
# AWS AI Practitioner (AIF-C01)
# Domain 2 - Task Statement 2.1 (Lesson 2)
## Tokenization, Embeddings & Transformer

---

# 📌 Pre-trained Foundation Models

Generative AI project start karte waqt hume model train karne ki zarurat nahi hoti.

AWS pe already **Pre-trained Foundation Models** available hote hain.

Inhe directly use ya fine-tune kiya ja sakta hai.

Example:
- SageMaker JumpStart
- Amazon Titan Models

---

# Tokenizer

LLM directly human language nahi samajhta.

Tokenizer ka kaam hota hai:

```
Human Text
      ↓
   Tokens
      ↓
 Token IDs
```

Har token ko ek unique **Token ID (Input ID)** milti hai.

Example:

```
"I love AWS"

↓

"I" → 101

"love" → 502

"AWS" → 887
```

Ye IDs model ko input ke roop me di jati hain.

---

# Vocabulary

Vocabulary = Model jitne unique tokens ko jaanta hai.

Har token ka ek unique Token ID hota hai.

Example:

```
Hello → 125

Cloud → 890

AI → 311
```

---

# Vector

Vector = Ordered list of numbers.

Example:

```
[0.42, 1.53, -0.75, 0.91]
```

AI me vectors words, sentences ya images ko numerical form me represent karte hain.

Machine Learning sirf numbers par kaam karta hai.

---

# Why Vectors?

Vectors help model to understand:

- Meaning
- Relationships
- Similarity
- Context

Words similar honge to unke vectors bhi nearby honge.

Example:

```
King 👑

Queen 👑

Prince 🤴

Princess 👸
```

Ye sab vector space me ek dusre ke close hote hain.

---

# Embeddings

Embedding = Word ya kisi bhi entity ka numerical vector representation.

Simple words me:

**Text → Numbers (Vectors)**

Embeddings semantic meaning ko capture karti hain.

Ye represent kar sakti hain:

- Text
- Images
- Audio
- Video

---

# Semantic Meaning

Semantic Meaning = Actual meaning of words.

Example:

```
Dog

Puppy

Cat
```

Dog aur Puppy ke embeddings ek dusre ke close honge.

Dog aur Car ke embeddings kaafi door honge.

---

# Vector Space

Vector Space ek mathematical space hota hai jahan embeddings store hote hain.

Simple analogy:

Excel Spreadsheet

↓

Har cell ki ek location hoti hai.

Waise hi har embedding ki vector space me ek position hoti hai.

Closer vectors

↓

More Similar Meaning

Far vectors

↓

Less Similar Meaning

---

# Transformer Architecture

Modern LLMs ka backbone:

**Transformer**

Introduced in:

**2017 Paper**

**Attention Is All You Need**

Transformer language ko context ke saath samajhta hai.

---

# Self-Attention

Transformer ka sabse important feature:

**Self-Attention Mechanism**

Ye decide karta hai ki sentence ke kaunse words jyada important hain.

Example:

```
The cat sat on the mat because it was tired.
```

"it"

↓

Cat ko refer karta hai.

Self-attention ye relationship identify karta hai.

---

# Benefits of Self-Attention

- Better Context Understanding
- Long Sentences Handle Karna
- Important Words Identify Karna
- Better Accuracy

---

# Query, Key & Value (QKV)

Self-attention me har token ke 3 vectors bante hain:

- Query (Q)
- Key (K)
- Value (V)

Inki help se model decide karta hai ki kis token par kitna attention dena hai.

**Exam Note:** Low-level calculation yaad rakhne ki zarurat nahi hai.

Bas itna yaad rakho:

**Q + K + V → Self-Attention**

---

# Attention Scores

Self-attention calculate karta hai:

**Attention Score**

High Score

↓

Word important hai.

Low Score

↓

Word less important hai.

Final output attention scores ke basis par generate hota hai.

---

# Position Embeddings

Transformer naturally word order nahi samajhta.

Isliye use kiye jaate hain:

**Position Embeddings**

Ye batate hain:

- Word kis position par hai.
- Sentence ka order kya hai.

Example:

```
Dog bites man

≠

Man bites dog
```

Words same hain,

Position alag hai,

Meaning completely different hai.

---

# Inference in Transformer

Inference ke time process:

```
Prompt

↓

Tokenizer

↓

Token IDs

↓

Embeddings

↓

Transformer

↓

Self-Attention

↓

Next Token Prediction

↓

Completion
```

---

# Transformer Advantages

- Long-range dependencies samajhta hai.
- Parallel processing karta hai.
- Fast training.
- Better context understanding.
- Human-like responses generate karta hai.

---

# Encoder & Decoder

Transformer architecture me generally do main parts hote hain:

### Encoder

Input ko understand karta hai.

### Decoder

Final output generate karta hai.

**Exam Tip:** Sirf encoder aur decoder ka basic role yaad rakhna hai.

Internal working yaad karne ki zarurat nahi.

---

# Positional Encoding

Positional Encoding token ki position encode karta hai.

Isse model sentence ka order samajh pata hai.

Without positional encoding,

Transformer ko word sequence ka pata nahi chalega.

---

# Residual Connections & Layer Normalization

Training ko stable aur efficient banane ke liye Transformer use karta hai:

- Residual Connections
- Layer Normalization

AWS Exam ke liye inki internal working important nahi hai.

Bas naam yaad rakhna kaafi hai.

---

# Important Exam Notes ⭐

Remember:

- Tokenizer → Text ko Token IDs me convert karta hai.
- Vocabulary → Known Tokens ka collection.
- Vector → Numerical Representation.
- Embedding → Meaning wala Vector.
- Similar Meaning → Similar Embeddings.
- Transformer → Backbone of Modern LLMs.
- Self-Attention → Important words identify karta hai.
- Position Embeddings → Word order preserve karte hain.
- Encoder → Input samajhta hai.
- Decoder → Output generate karta hai.
- Inference → Prompt se Completion generate karna.
----------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------
# AWS AI Practitioner (AIF-C01)
# Domain 2 - Task Statement 2.1 (Lesson 3)
## Large Language Models, Multimodal Models & Diffusion Models

---

# 📌 Why are Large Models Better?

Researchers ne observe kiya hai ki:

**Jitna bada model hoga, utni uski capability zyada hogi.**

Large models:

- Better reasoning karte hain.
- Better responses generate karte hain.
- Kam examples (In-context Learning) ki zarurat padti hai.
- Har task ke liye alag training ki zarurat nahi hoti.

---

# Why Can't We Keep Increasing Parameters?

Zyada parameters hone ke advantages hain, lekin kuch limitations bhi hain.

### Challenges:

- Training bahut expensive hoti hai.
- Huge computing resources chahiye.
- Bahut saare GPUs ki requirement hoti hai.
- Training me bahut time lagta hai.
- Huge amount of electricity consume hoti hai.

**Exam Tip:** Bigger model ≠ Always practical

---

# Pre-training

LLM pehle huge amount of data par train hota hai.

Is process ko kehte hain:

**Pre-training**

Training data sources:

- Internet
- Books
- Research Papers
- Articles
- Documents

Ye data GB, TB ya PB (Petabytes) tak ho sakta hai.

---

# Self-Supervised Learning

LLMs generally use:

**Self-Supervised Learning**

Isme manually labels dene ki zarurat nahi hoti.

Model khud next word predict karke language patterns learn karta hai.

Example:

```
I love ______

↓

India
```

Model khud answer predict karke learn karta hai.

---

# Model Weights

Training ke time model continuously apne:

**Weights**

update karta rehta hai.

Goal:

Loss ko minimum karna.

Better weights

↓

Better predictions

↓

Better responses

---

# Loss Function

Loss Function batata hai ki model ki prediction kitni galat hai.

High Loss

↓

Poor Prediction

Low Loss

↓

Good Prediction

Training ka objective:

**Loss ko minimize karna.**

---

# GPUs in Training

Large Language Models ko train karne ke liye use hote hain:

**GPUs (Graphics Processing Units)**

Reason:

- Parallel processing
- Fast matrix calculations
- Faster Deep Learning training

---

# Data Quality

Internet se directly data use nahi kiya jata.

Training se pehle data clean kiya jata hai.

Data Processing me:

- Duplicate remove hote hain.
- Harmful content remove hota hai.
- Biased data reduce kiya jata hai.
- Low-quality data remove hota hai.

Sirf high-quality data training ke liye use hota hai.

---

# Data Curation

Data ko clean aur filter karne ki process:

**Data Curation**

Interesting Fact:

Internet se collect kiye gaye data ka sirf **1–3%** hi final training ke liye use hota hai.

---

# Unimodal Model

Unimodal = Sirf **ek type ka data** process karta hai.

Example:

Text → Text

LLMs jaise ChatGPT ke basic text models.

---

# Multimodal Model

Multimodal = Multiple data types ko samajh aur generate kar sakta hai.

Example:

- Text
- Image
- Audio
- Video

Ek hi model multiple modalities handle karta hai.

---

# Examples of Multimodal Tasks

### Image Captioning

Image

↓

Text Description

---

### Visual Question Answering (VQA)

Image dekar uske baare me question puchna.

Example:

```
Image:

Dog playing football.

Question:

What is the dog doing?
```

---

### Text-to-Image Generation

Text Prompt

↓

AI Generated Image

Popular Models:

- DALL·E
- Stable Diffusion
- Midjourney

---

# Applications of Multimodal AI

- Marketing
- Product Design
- Customer Service
- Chatbots
- Virtual Avatars
- Image Search
- Content Creation

---

# Diffusion Models

Diffusion Models image aur audio generation ke liye popular Generative AI models hain.

Ye gradually random noise ko remove karke final output generate karte hain.

Simple Flow:

```
Random Noise

↓

Remove Noise Step by Step

↓

Final Image
```

---

# Three Main Components of Diffusion Models

### 1. Forward Diffusion

Original image me gradually noise add kiya jata hai.

Image

↓

Noise

↓

Complete Random Noise

---

### 2. Reverse Diffusion

Model gradually noise remove karta hai.

Noise

↓

Cleaner Image

↓

Final Image

---

### 3. Stable Diffusion

Stable Diffusion image ko directly pixel space me process nahi karta.

Ye **latent space** me image represent karta hai.

Result:

- Faster generation
- Less computation
- Better efficiency

---

# Latent Space

Latent Space = Image ka compressed numerical representation.

Stable Diffusion isi compressed representation par kaam karta hai.

Isse image generation fast aur memory efficient hoti hai.

---

# Advantages of Diffusion Models

Compared to GANs aur VAEs:

- Higher image quality
- Better diversity
- More stable training
- Better consistency
- Easier to train

---

# Examples of Diffusion Models

### Stable Diffusion

Image Generation

---

### Whisper

Speech Recognition

Speech Translation

---

### AudioLM

Audio Generation

---

# AWS Support for Diffusion Models

AWS services jo Diffusion Models support karti hain:

- Amazon SageMaker
- SageMaker JumpStart
- TensorFlow
- PyTorch

Inki help se:

- Pre-trained models use kar sakte hain.
- Fine-tuning kar sakte hain.
- Deployment easily kar sakte hain.

---

# Important Exam Notes ⭐

Remember:

- Large Models → Better capability
- More Parameters → Better performance but expensive training
- Pre-training → Huge unlabeled data par training
- Self-Supervised Learning → Model khud learn karta hai
- GPUs → Large model training ke liye use hote hain
- Data Curation → Training se pehle data clean karna
- Unimodal → One data type
- Multimodal → Multiple data types
- Diffusion Model → Noise remove karke image generate karta hai
- Forward Diffusion → Noise add karna
- Reverse Diffusion → Noise remove karna
- Stable Diffusion → Latent Space me image generate karta hai
- SageMaker JumpStart → Pre-trained models provide karta hai
-------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------
# AWS AI Practitioner (AIF-C01)
# Domain 2 - Task Statement 2.1 (Lesson 4)
## Generative AI Tasks & Use Cases

---

# 📌 Large Language Models (LLMs)

LLMs ek type ke **Generative AI Models** hote hain.

Ye bina fine-tuning ke bhi bahut saare different tasks perform kar sakte hain.

Example:

- Content Writing
- Translation
- Summarization
- Question Answering
- Code Generation

---

# Text Generation

Generative AI ka sabse common use case hai:

**Text Generation**

Isme AI naya text create karta hai.

Examples:

- Articles
- Blogs
- Emails
- Stories
- Reports
- Social Media Posts

---

# Text Rewriting

AI existing text ko rewrite ya modify bhi kar sakta hai.

Use Cases:

- Easy language me convert karna
- Formal ↔ Informal
- Grammar improve karna
- Different audience ke liye content modify karna

Example:

Technical document

↓

Simple language for beginners

---

# Text Summarization

AI large document ka short summary bana sakta hai.

Goal:

Important information ko retain karte hue text ko short banana.

Examples:

- News Articles
- Research Papers
- Technical Documentation
- Financial Reports
- Legal Documents

---

# Information Extraction

Generative AI kisi document se important information nikal sakta hai.

Examples:

- Names
- Dates
- Locations
- Company Names
- Important Keywords

---

# Question Answering (QA)

AI natural language questions ka answer de sakta hai.

Example:

```
Question:

What is Cloud Computing?

↓

AI Answer
```

---

# Classification

Generative AI content ko categories me classify bhi kar sakta hai.

Examples:

- Spam Detection
- Positive / Negative Review
- Topic Classification
- Email Categorization

---

# Harmful Content Detection

AI harmful ya unsafe content identify kar sakta hai.

Examples:

- Hate Speech
- Offensive Language
- Toxic Content
- Fake Information

---

# Translation

AI ek language se doosri language me translation kar sakta hai.

Example:

English

↓

Hindi

Ya

Hindi

↓

French

---

# Recommendation Systems

Generative AI personalized recommendations de sakta hai.

Examples:

- Movies
- Products
- Music
- Videos

---

# Personalized Marketing

Customer ke interest ke according:

- Ads
- Emails
- Product Recommendations

automatically generate kiye ja sakte hain.

---

# Chatbots & Customer Support

Generative AI intelligent chatbots bana sakta hai.

Use Cases:

- Customer Support
- Banking Assistant
- Shopping Assistant
- Healthcare Assistant

---

# Search

Generative AI traditional keyword search ko improve karta hai.

Ye user ke intent ko samajhkar better search results provide karta hai.

---

# Code Generation

Generative AI software developers ki productivity increase karta hai.

Ye generate kar sakta hai:

- Code Snippets
- Functions
- Complete Programs
- Unit Tests
- Documentation

---

# Code Completion

Typing ke time AI automatically next code suggest karta hai.

Example:

```
for(...)
```

↓

Remaining code automatically suggest ho jata hai.

---

# Code Translation

AI ek programming language ko doosri language me convert kar sakta hai.

Example:

```
Java

↓

Python

↓

JavaScript
```

---

# AWS Services for Generative AI

## Amazon Bedrock

Provides pre-trained Foundation Models for:

- Text Generation
- Image Generation
- Audio Generation

Models ko fine-tune bhi kiya ja sakta hai.

---

## Amazon Titan

Amazon ke Foundation Models.

Supports:

- Text
- Image
- Embeddings

---

## Amazon SageMaker

ML aur Generative AI models ko:

- Build
- Train
- Fine-tune
- Deploy

karne ke liye use hota hai.

---

## Amazon Q Developer

Former Name:

**Amazon CodeWhisperer**

Developer ke liye AI coding assistant.

Features:

- Code Suggestions
- Code Completion
- Function Generation
- Bug Fixing
- Code Explanation

---

# Amazon Sumerian

Use hota hai:

- 3D Content Creation
- Virtual Production
- AR/VR Experiences

---

# Generative AI as a Developer Tool

Developers AI ka use kar sakte hain:

- Faster Coding
- Bug Fixing
- Documentation
- Code Review
- Code Translation
- Code Completion

Isse software development fast ho jata hai.

---

# Generative AI Architectures

Different Generative AI architectures alag-alag tasks ke liye use hote hain.

## 1. Transformers

Best for:

- Text Generation
- LLMs
- Chatbots

Examples:

- ChatGPT
- Claude
- Titan
- Llama

---

## 2. GAN (Generative Adversarial Network)

Best for:

- Image Generation
- Face Generation
- Deepfake Images

---

## 3. VAE (Variational Autoencoder)

Best for:

- Image Generation
- Data Compression
- Feature Learning

---

# Choosing the Right Architecture

Architecture choose karte waqt consider karo:

- Problem Statement
- Dataset
- Required Output
- Accuracy
- Performance

Har architecture ke apne:

- Advantages
- Limitations

hote hain.

---

# Important Exam Notes ⭐

Remember:

- LLMs → Multiple tasks bina fine-tuning ke perform kar sakte hain.
- Text Generation → Naya content create karna.
- Text Rewriting → Existing content modify karna.
- Summarization → Long text ko short banana.
- Information Extraction → Important data identify karna.
- QA → Natural language questions ka answer.
- Code Generation → AI programming me help karta hai.
- Amazon Bedrock → Foundation Models.
- Amazon Titan → AWS Foundation Models.
- Amazon SageMaker → Build, Train, Deploy ML Models.
- Amazon Q Developer → AI Coding Assistant.
- Amazon Sumerian → 3D & Virtual Content.
- Transformer → Text-based tasks.
- GAN → Image Generation.
- VAE → Image Generation & Data Compression.
-------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------
# AWS AI Practitioner (AIF-C01)
# Domain 2 - Task Statement 2.1 (Lesson 5)
## Generative AI Project Lifecycle

---

# 📌 Generative AI Project Lifecycle

Ek Generative AI project idea se deployment tak multiple stages se guzarta hai.

Main lifecycle:

```
Identify Use Case
        ↓
Experiment & Select
        ↓
Adapt, Align & Augment
        ↓
Evaluate
        ↓
Deploy & Iterate
        ↓
Monitor
```

---

# 1. Identify Use Case

Sabse pehla aur sabse important step.

Yahan decide karte hain:

- Problem kya hai?
- AI kis task ke liye use hoga?
- Expected output kya hai?

**Exam Tip:** Project ki success ka sabse important factor clear problem definition hai.

---

# 2. Experiment & Select

Is stage me:

- Data collect karte hain.
- Data process karte hain.
- Suitable Foundation Model choose karte hain.
- Different prompts aur models test karte hain.

Goal:

Best model select karna.

---

# 3. Adapt, Align & Augment

Selected model ko application ke according improve kiya jata hai.

Methods:

- Prompt Engineering
- In-context Learning
- Fine-Tuning
- RLHF (Reinforcement Learning from Human Feedback)

Goal:

Model ko business requirements ke according align karna.

---

# 4. Evaluate

Model ko evaluate kiya jata hai.

Check karo:

- Accuracy
- Quality
- Reliability
- Cost
- Performance

Agar result achha nahi aaye,

to previous stage me wapas jaakar improve karte hain.

---

# 5. Deploy & Iterate

Satisfied hone ke baad model production me deploy karte hain.

Deployment ke baad:

- User Feedback collect hota hai.
- Updates release hote hain.
- Performance improve hoti rehti hai.

Ye iterative process hai.

---

# 6. Monitor

Deployment ke baad continuously monitor karna zaruri hai.

Monitor:

- Performance
- Errors
- Security
- Cost
- Scalability
- User Feedback

Model ko regularly update bhi kiya jata hai.

---

# AI Development Stages

AI project ko broadly 3 stages me divide kiya ja sakta hai.

## Stage 1 - Define & Prepare

Tasks:

- Define Objectives
- Collect Data
- Process Data
- Select Model
- Train Model

---

## Stage 2 - Build & Improve

Tasks:

- Feature Engineering
- Model Building
- Testing
- Validation
- Optimization
- Scaling

---

## Stage 3 - Deploy & Maintain

Tasks:

- Evaluation
- Deployment
- Feedback Collection
- Updates
- Security
- Scalability

---

# Foundation Model Lifecycle

AWS Exam ke according Foundation Model lifecycle:

```
Data Selection
      ↓
Model Selection
      ↓
Pre-training
      ↓
Fine-tuning
      ↓
Evaluation
      ↓
Deployment
      ↓
Feedback
```

---

# Scope Definition

Project start karne se pehle scope clearly define karo.

Questions:

- Model kya karega?
- General-purpose hoga ya specific task?
- Long text generate karega ya sirf Question Answering?

Clear scope:

- Time bachata hai.
- Compute cost kam karta hai.
- Better model selection me help karta hai.

---

# Train from Scratch vs Existing Model

Development start karte waqt do options hote hain.

## Option 1

Train Model from Scratch

Advantages:

- Fully customized

Disadvantages:

- Very expensive
- Huge data required
- Huge compute required

---

## Option 2

Existing Foundation Model

Advantages:

- Faster
- Cheaper
- Easy Deployment

Most real-world projects isi approach ko use karte hain.

---

# Improving Model Performance

Performance improve karne ka recommended order:

### Step 1

Prompt Engineering

↓

### Step 2

In-context Learning

↓

### Step 3

Few-shot / One-shot Examples

↓

### Step 4

Fine-Tuning (if required)

AWS exam me pehle Prompt Engineering try karna recommended hai.

---

# Fine-Tuning

Agar Prompt Engineering se expected performance na mile,

to model ko supervised learning ke through fine-tune kiya jata hai.

Goal:

Specific task me better performance.

---

# RLHF (Reinforcement Learning from Human Feedback)

RLHF ka full form:

**Reinforcement Learning from Human Feedback**

Purpose:

Model ko human preferences ke according train karna.

Benefits:

- Better responses
- Safer outputs
- More helpful answers

---

# Evaluation Metrics

Deployment se pehle evaluate karo:

- Accuracy
- Response Quality
- Reliability
- Cost
- Latency
- User Satisfaction

Evaluation ek continuous process hai.

---

# Deployment

Deployment ke time ensure karo:

- Model optimized ho.
- Infrastructure ready ho.
- Compute resources sufficient ho.
- Application smoothly work kare.

---

# Iterative Development

Generative AI development linear process nahi hota.

Flow:

```
Build

↓

Evaluate

↓

Improve

↓

Evaluate Again

↓

Deploy
```

Ye cycle continuously repeat hoti rehti hai.

---

# Limitations of LLMs

LLMs ki kuch limitations hoti hain.

## Hallucination

Model kabhi-kabhi galat ya imaginary information generate kar deta hai.

Example:

Aisa answer dena jo factually incorrect ho.

---

## Complex Reasoning

LLMs complex logical reasoning me mistakes kar sakte hain.

---

## Mathematics

Advanced mathematical calculations me errors ho sakte hain.

---

# Infrastructure Considerations

Deployment ke time sirf model hi enough nahi hota.

Infrastructure bhi important hota hai.

Consider:

- Compute Resources
- Scalability
- Security
- Monitoring
- Cost Optimization


# Important Exam Notes ⭐

Remember:

- Project Lifecycle → Identify → Experiment → Adapt → Evaluate → Deploy → Monitor
- Scope Definition → Sabse important step
- Existing Foundation Models → Mostly preferred
- Prompt Engineering → First optimization technique
- Fine-Tuning → Prompt Engineering ke baad
- RLHF → Human feedback se model improve karna
- Evaluation → Continuous process
- Deployment → Infrastructure + Monitoring
- Hallucination → AI incorrect information generate kar sakta hai
- LLMs → Complex reasoning aur mathematics me limitations hoti hain
--------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------
# AWS AI Practitioner (AIF-C01)
# Domain 2 - Task Statement 2.2 (Lesson 1)
## Capabilities & Limitations of Generative AI

---

# 📌 Generative AI for Business

Generative AI ek **General-Purpose Technology** hai.

Iska matlab hai ki ise sirf ek kaam ke liye nahi, balki bahut saare business problems solve karne ke liye use kiya ja sakta hai.

Examples:

- Content Creation
- Customer Support
- Marketing
- Software Development
- Healthcare
- Finance
- Education

---

# Advantages of Generative AI

## 1. Adaptability

Generative AI alag-alag domains me easily adapt ho sakta hai.

Example:

Ek hi LLM use ho sakta hai:

- Chatbot
- Email Writing
- Code Generation
- Translation

---

## 2. Responsiveness

Generative AI user ke prompt ka instantly response generate karta hai.

Benefits:

- Faster decision making
- Better customer experience
- Real-time assistance

---

## 3. Simplicity

Traditional AI applications banana difficult aur expensive tha.

Generative AI ki help se AI applications banana:

- Easier
- Faster
- Cheaper

ho gaya hai.

---

# Real-Life Uses of AI

Hum roz AI use karte hain.

Examples:

- Web Search
- Credit Card Fraud Detection
- Product Recommendations
- Voice Assistants
- Email Spam Detection

Generative AI in applications ko aur powerful bana raha hai.

---

# Business Benefits

Generative AI businesses ko help karta hai:

- Development Cost kam karne me
- Faster application development
- Better productivity
- Automation
- Improved customer service

---

# Responsible AI

Generative AI powerful hai,

lekin ise responsibly use karna zaruri hai.

AI systems hone chahiye:

- Fair
- Ethical
- Safe
- Reliable

AWS Responsible AI concepts Domain 4 me detail me cover honge.

---

# Limitations of Generative AI

Generative AI har problem solve nahi kar sakta.

Iski kuch important limitations hain.

---

# 10-Year-Old Rule

Ek simple rule:

**Agar ek 10 saal ka bachcha instructions follow karke task kar sakta hai, to LLM bhi usually kar sakta hai.**

Example:

✔ Email complaint identify karna

✔ Text summarize karna

✔ Translation

Ye tasks LLM easily kar leta hai.

---

# When LLM Struggles

Agar information hi available nahi hai,

to LLM accurate answer nahi de sakta.

Example:

```
Write about a brand-new AWS service
```

Agar model ne us service ke baare me kabhi nahi dekha,

to wo sirf generic answer dega.

---

# Need for Context

LLM ko better answer dene ke liye context dena zaruri hota hai.

Example:

```
Blog Post

↓

Prompt

↓

Detailed Answer
```

Without context:

Generic Response

With context:

Accurate Response

---

# Memory Limitation

LLMs permanently conversations remember nahi karte.

Har naya prompt ek naye task ki tarah treat hota hai.

Isliye model automatically:

- Company Rules
- Writing Style
- Business Knowledge

future conversations ke liye remember nahi karta.

---

# Fine-Tuning

Agar business ko specific behavior chahiye,

to Foundation Model ko fine-tune kiya ja sakta hai.

Fine-tuning se model:

- Company style learn karta hai.
- Domain knowledge improve hoti hai.
- Better business-specific responses deta hai.

---

# Prompt vs Fine-Tuning

### Prompt Engineering

Temporary guidance

↓

Current prompt ke liye.

---

### Fine-Tuning

Permanent learning

↓

Specific business use case ke liye.

---

# Best Practices

Generative AI use karte waqt:

- Clear prompts likho.
- Required context provide karo.
- Output verify karo.
- Responsible AI follow karo.
- Sensitive data avoid karo.

---

# Business Examples

### Customer Support

AI FAQs ka answer de sakta hai.

---

### Marketing

Ads aur social media content generate kar sakta hai.

---

### Software Development

Code generate aur explain kar sakta hai.

---

### Finance

Reports summarize kar sakta hai.

---

### Education

Study notes aur explanations generate kar sakta hai.

---

# Important Exam Notes ⭐

Remember:

- Generative AI → General-Purpose Technology
- Main Advantages → Adaptability, Responsiveness, Simplicity
- Business Benefits → Faster development + Lower cost
- Responsible AI → Fair, Ethical, Safe
- LLM → Information ke bina accurate answer nahi de sakta
- Better Context → Better Output
- LLM → Long-term memory automatically maintain nahi karta
- Fine-Tuning → Business-specific knowledge add karta hai
- Prompt Engineering → Temporary improvement
- Fine-Tuning → Long-term customization
-------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------
# AWS AI Practitioner (AIF-C01)
# Domain 2 - Task Statement 2.2 (Lesson 2)
## Fine-Tuning, Hallucination & Model Evaluation

---

# 📌 Instruction Fine-Tuning

Instruction Fine-Tuning ka goal hai model ko human instructions better samjhana.

Is process ke baad model:

- Better prompts understand karta hai.
- More natural responses deta hai.
- Human-like language generate karta hai.
- Specific tasks me better perform karta hai.

---

# Benefits of Fine-Tuning

Fine-tuning se:

- Better Accuracy
- Better Response Quality
- Natural Language
- Domain-specific Knowledge
- Improved User Experience

milta hai.

---

# Problems in LLMs

Large Language Models perfect nahi hote.

Kabhi-kabhi ye:

- Toxic language generate karte hain.
- Aggressive responses dete hain.
- Harmful information provide kar dete hain.
- Incorrect facts bata dete hain.

Reason:

Training data internet se aata hai,

jisme good aur bad dono type ka content hota hai.

---

# Hallucination

Hallucination = Jab AI confidently galat ya imaginary information generate kare.

Example:

User:

```
Best treatment for diabetes?
```

AI:

```
High-carb diet is the best treatment.
```

Ye factually incorrect answer hai.

Isko **Hallucination** kehte hain.

---

# How to Handle Hallucinations

Kabhi bhi AI ke answer par blindly trust mat karo.

Always verify from:

- Official Documentation
- Trusted Websites
- Research Papers
- Government Sources

AI assistant hai,

final authority nahi.

---

# Harmful Content

LLMs ko harmful content generate nahi karna chahiye.

Examples:

- Hate Speech
- Offensive Language
- Illegal Activities
- Discrimination
- Violence Instructions

Responsible AI ka objective hai in outputs ko reduce karna.

---

# Human Values in AI

Responsible AI ke 3 important principles:

## Helpfulness

Useful aur helpful responses dena.

---

## Honesty

Correct information provide karna.

Agar answer nahi pata,

to guess nahi karna.

---

## Harmlessness

Unsafe ya harmful content avoid karna.

---

# Human Feedback

Model ko human preferences ke according improve karne ke liye:

**Human Feedback** use kiya jata hai.

Ye help karta hai:

- Better responses
- Safer outputs
- Less toxicity
- Better alignment

---

# RLHF

RLHF = Reinforcement Learning from Human Feedback

Purpose:

Model ko human expectations ke according improve karna.

Benefits:

- Helpful
- Honest
- Harmless

responses generate karna.

---

# Model Interpretability

Interpretability ka matlab:

**Model ne prediction kyu diya?**

Agar reason easily samajh aaye,

to model highly interpretable hai.

---

# Performance vs Interpretability

Ek important trade-off hota hai.

### High Interpretability

Advantages:

- Easy to understand
- Easy to explain

Disadvantage:

- Lower performance

---

### High Performance Models

Examples:

Deep Neural Networks

Advantages:

- Better accuracy

Disadvantage:

- Difficult to explain

---

# Types of Model Interpretability

## 1. Intrinsic Analysis

Simple models ke liye use hota hai.

Characteristics:

- Low Complexity
- Easy to Understand
- High Interpretability

---

## 2. Post Hoc Analysis

Complex models ke liye use hota hai.

Examples:

- Neural Networks
- Deep Learning Models

Ye trained model ke outputs ko explain karta hai.

---

# Local vs Global Interpretation

## Local Interpretation

Sirf ek prediction ko explain karta hai.

Example:

Ek customer ko loan reject kyu hua?

---

## Global Interpretation

Pure model ka overall behavior explain karta hai.

Example:

Model generally loan approvals kaise decide karta hai?

---

# Model Evaluation

Fine-tuning ke baad model evaluate karna bahut important hai.

Evaluation se pata chalta hai:

- Model improve hua ya nahi.
- Accuracy kitni hai.
- Response quality kaisi hai.

---

# Traditional ML Evaluation

Traditional ML me output already known hota hai.

Isliye easily metrics calculate kar sakte hain.

Example:

- Accuracy
- Precision
- Recall

---

# LLM Evaluation

LLMs deterministic nahi hote.

Ek hi prompt par multiple valid answers aa sakte hain.

Isliye evaluation difficult hota hai.

---

# Deterministic vs Non-Deterministic

## Deterministic Model

Same input

↓

Same output

Har baar.

---

## Non-Deterministic Model

Same input

↓

Different but valid outputs

possible hain.

LLMs isi category me aate hain.

---

# ROUGE

Full Form:

**Recall-Oriented Understudy for Gisting Evaluation**

Use:

Summary quality evaluate karne ke liye.

Comparison:

AI Summary

vs

Human Summary

---

# BLEU

Full Form:

**Bilingual Evaluation Understudy**

Use:

Machine Translation evaluate karne ke liye.

Comparison:

AI Translation

vs

Human Translation

---

# Evaluation Metrics

LLM evaluation me common metrics:

- ROUGE → Summarization
- BLEU → Translation

AWS exam me inka basic purpose yaad rakhna hai.

---

# Important Exam Notes ⭐

Remember:

- Instruction Fine-Tuning → Human prompts better understand karna.
- Hallucination → Confident but incorrect answer.
- AI Output → Always verify from trusted sources.
- RLHF → Human Feedback se model improve karna.
- Responsible AI → Helpful, Honest, Harmless.
- Interpretability → Prediction ka reason samajhna.
- High Interpretability → Easy explanation, lower complexity.
- High Performance Models → Better accuracy, difficult explanation.
- Intrinsic Analysis → Simple models.
- Post Hoc Analysis → Complex models.
- Local Interpretation → Single prediction.
- Global Interpretation → Overall model behavior.
- Traditional ML → Deterministic.
- LLM → Non-deterministic.
- ROUGE → Summarization Evaluation.
- BLEU → Translation Evaluation.
-----------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------
# AWS AI Practitioner (AIF-C01)
# Domain 2 - Task Statement 2.2 (Lesson 3)
## Selecting Generative AI Models & Business Metrics

---

# 📌 Choosing the Right Generative AI Model

Har Generative AI model har problem ke liye suitable nahi hota.

Model select karte waqt in factors ko consider karo:

- Model Type
- Performance
- Business Requirements
- Capabilities
- Constraints
- Compliance

---

# Model Types

Foundation Models alag-alag types ke content generate kar sakte hain.

### Text Models

Use Cases:

- Chatbots
- Content Writing
- Summarization
- Translation

---

### Image Models

Use Cases:

- Image Generation
- Image Editing
- Product Design

---

### Code Models

Use Cases:

- Code Generation
- Code Completion
- Bug Fixing

---

### Video Models

Use Cases:

- Video Generation
- Animation
- Video Editing

---

### Embedding Models

Use Cases:

- Semantic Search
- Recommendation Systems
- Similarity Search
- RAG Applications

---

# Selecting the Right Model

Model choose karte waqt dekho:

- Kis type ka data hai?
- Kis type ka output chahiye?
- Accuracy requirement kya hai?
- Cost kitni acceptable hai?
- Response speed kitni chahiye?

---

# Popular Generative AI Architectures

## 1. VAE (Variational Autoencoder)

Best For:

- Image Generation
- Data Compression
- Feature Learning

---

## 2. GAN (Generative Adversarial Network)

Best For:

- Realistic Image Generation
- Face Generation
- Deepfake Images

---

## 3. Autoregressive Models

Best For:

- Text Generation
- Language Modeling

Examples:

- GPT Family
- LLaMA
- Claude

---

# Foundation Models (FMs)

Foundation Models huge unlabeled datasets par trained hote hain.

Features:

- Large Scale
- General Purpose
- Multiple Tasks
- Fine-Tunable

Ye Generative AI applications ka starting point hote hain.

---

# Examples of Foundation Models

### Stable Diffusion

Best for:

Image Generation

---

### GPT-4

Best for:

Natural Language Processing

- Chatbots
- Writing
- Coding
- Summarization

---

# Why Foundation Models?

Foundation Models:

- Language samajhte hain.
- Conversation kar sakte hain.
- Images generate kar sakte hain.
- Code likh sakte hain.
- Multiple tasks perform kar sakte hain.

---

# Business KPIs (Key Performance Indicators)

Generative AI ki success measure karne ke liye business metrics use kiye jate hain.

Common KPIs:

- Accuracy
- Efficiency
- Conversion Rate
- Revenue
- Customer Satisfaction
- Customer Lifetime Value

---

# Accuracy

Measure karta hai:

AI kitne correct outputs generate kar raha hai.

Higher Accuracy

↓

Better AI Performance

---

# Efficiency

Measure karta hai:

AI kitni efficiently task complete kar raha hai.

Metrics:

- Faster Processing
- Lower Manual Work
- Better Productivity

---

# Conversion Rate

Business metric.

Measure karta hai:

Kitne users desired action perform karte hain.

Example:

Visitors

↓

Customers

---

# Average Revenue Per User (ARPU)

Formula:

```
Total Revenue

÷

Total Users
```

Higher ARPU

↓

Better Business Performance

---

# Customer Lifetime Value (CLTV)

CLTV batata hai:

Ek customer company ko lifetime me kitna revenue dega.

Higher CLTV

↓

Long-term Business Growth

---

# How to Increase CLTV?

Strategies:

- Loyalty Programs
- Personalized Experience
- Cross Selling
- Customer Feedback
- Better Customer Support

---

# Cross-Domain Performance

Measure karta hai:

Model kitni achhi tarah multiple domains me perform karta hai.

Example:

Ek hi model:

- Healthcare
- Finance
- Education

sabme useful ho.

---

# Enterprise Integration

Business me Foundation Models ko existing systems ke saath integrate karna zaruri hota hai.

Examples:

- Databases
- ERP Systems
- CRM Systems

---

# ERP

ERP = Enterprise Resource Planning

Purpose:

Business operations manage karna.

Examples:

- Finance
- Inventory
- HR
- Supply Chain

---

# CRM

CRM = Customer Relationship Management

Purpose:

Customer information aur relationships manage karna.

Examples:

- Customer Support
- Sales
- Marketing

---

# Challenges with Foundation Models

Organizations ko ensure karna hota hai:

- High-quality output
- Less hallucination
- Better business alignment
- Existing systems ke saath integration
- Cost-effective deployment

---

# Output Quality Metrics

AI output evaluate karne ke important metrics:

### Relevance

Output user ke question se related hai ya nahi.

---

### Accuracy

Information correct hai ya nahi.

---

### Coherence

Response logical aur well-structured hai ya nahi.

---

### Appropriateness

Response context ke according suitable hai ya nahi.

---

# Operational Metrics

Business productivity measure karne ke metrics:

- Task Completion Rate
- Manual Effort Reduction
- Error Rate
- Operational Cost
- Processing Time

---

# ROI (Return on Investment)

Business evaluate karta hai:

```
Benefits

vs

Cost
```

Agar AI implementation se benefit cost se zyada ho,

to ROI positive hota hai.

---

# Continuous Monitoring

Generative AI models ko continuously monitor karna chahiye.

Monitor:

- Performance
- Accuracy
- Cost
- User Satisfaction
- Business Goals

AI systems ko regular review aur improvement ki zarurat hoti hai.

---

# Important Exam Notes ⭐

Remember:

- Model Selection → Requirements ke according hota hai.
- Text Model → NLP Tasks.
- Image Model → Image Generation.
- Code Model → Programming Tasks.
- Embedding Model → Search & RAG.
- Foundation Models → Large unlabeled datasets par trained hote hain.
- Stable Diffusion → Image Generation.
- GPT-4 → Text Generation.
- Accuracy → Correct outputs.
- Efficiency → Faster & productive workflow.
- Conversion Rate → Visitors se Customers.
- ARPU → Revenue per User.
- CLTV → Customer Lifetime Value.
- ERP → Enterprise Resource Planning.
- CRM → Customer Relationship Management.
- Output Quality → Relevance + Accuracy + Coherence + Appropriateness.
- ROI → Cost vs Benefit.
- Continuous Monitoring → AI systems ko regularly evaluate aur improve karna.
------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------
# AWS AI Practitioner (AIF-C01)
# Domain 2 - Task Statement 2.3 (Lesson 1)
## AWS Infrastructure & Technologies for Generative AI

---

# 📌 Why Use AWS for Generative AI?

AWS Generative AI services applications ko build aur deploy karna easy banati hain.

Main Advantages:

- Accessibility
- Lower Barrier to Entry
- Cost-Effectiveness
- Faster Development
- Speed to Market
- Better Business Outcomes

---

# Benefits of AWS Generative AI Services

## Accessibility

AWS pre-built AI services provide karta hai.

Isliye developers ko sab kuch scratch se build nahi karna padta.

---

## Lower Barrier to Entry

Generative AI build karne ke liye expensive infrastructure kharidne ki zarurat nahi.

AWS cloud par required resources provide karta hai.

---

## Cost-Effectiveness

Pay-as-you-go model.

Sirf utna hi pay karo jitna resources use karte ho.

---

## Faster Development

AWS ke pre-trained models aur managed services development ko fast bana dete hain.

---

## Speed to Market

Application jaldi deploy hoti hai.

Business quickly customers tak product pahucha sakta hai.

---

## Meet Business Objectives

AWS services:

- Productivity improve karti hain.
- Cost reduce karti hain.
- AI adoption fast karti hain.

---

# Transfer Learning

Transfer Learning = Existing pre-trained model ko use karke naya model banana.

Scratch se training ki zarurat nahi hoti.

Flow:

```
Pre-trained Model

↓

New Dataset

↓

Fine-Tuning

↓

New Model
```

---

# Benefits of Transfer Learning

- Less Training Time
- Smaller Dataset Required
- Lower Cost
- Better Accuracy
- Faster Development

---

# SageMaker JumpStart

Amazon SageMaker JumpStart pre-built resources provide karta hai.

Includes:

- Foundation Models
- Datasets
- Algorithms
- Industry Solutions
- Sample Projects

Purpose:

Generative AI projects ko quickly start karna.

---

# AWS Cloud Adoption Framework (CAF-AI)

CAF-AI = Cloud Adoption Framework for AI, ML & Generative AI.

Purpose:

Organizations ko AI adoption roadmap provide karna.

Helps in:

- AI Strategy
- Planning
- Best Practices
- Collaboration
- Implementation

---

# Security in Generative AI

AWS ka top priority:

**Security**

Sensitive business data ko protect karna.

Examples:

- Personal Data
- Financial Data
- Operational Data
- Compliance Data

---

# Three Layers of AWS Generative AI Stack

```
Applications
        ↑
Models & AI Services
        ↑
Infrastructure
```

---

# Layer 1 - Infrastructure Layer

Bottom layer.

Provides:

- Compute Resources
- Storage
- Networking
- AI Hardware

Purpose:

Foundation Models ko train aur run karna.

---

# Layer 2 - Models & AI Services

Middle layer.

Provides:

- Foundation Models
- AI Services
- Fine-Tuning
- Model Deployment

Examples:

- Amazon Bedrock
- Amazon SageMaker

---

# Layer 3 - Application Layer

Top layer.

Applications jo AI use karti hain.

Examples:

- Chatbots
- Coding Assistants
- Content Generation
- Dashboards
- RAG Applications

---

# Specialized AI Hardware

AWS AI workloads ke liye specialized hardware provide karta hai.

Benefits:

- Better Performance
- Lower Cost
- Faster Training
- Faster Inference

---

# AWS Nitro System

AWS Nitro System ek security-focused hardware platform hai.

Purpose:

Amazon EC2 instances ko secure banana.

Benefits:

- Data Protection
- Workload Isolation
- Unauthorized Access Prevention

---

# AI Accelerator Chips

## AWS Inferentia

Purpose:

Model Inference

Benefits:

- Lower inference cost
- Faster predictions

---

## AWS Trainium

Purpose:

Model Training

Benefits:

- Faster training
- Better price-performance

---

# GPU Instances

AWS AI GPU instances:

- P4
- P5
- G5
- G6

Use Cases:

- Deep Learning
- LLM Training
- Image Processing
- Model Inference

---

# Foundation Models in AWS

Middle layer me services Foundation Models ko use karti hain.

Examples:

- Amazon Bedrock
- Amazon SageMaker

Capabilities:

- Train
- Fine-Tune
- Deploy
- Scale

---

# RAG (Retrieval-Augmented Generation)

RAG ek Generative AI architecture hai.

Working:

```
User Question

↓

Retrieve External Data

↓

LLM

↓

Better Response
```

Purpose:

Hallucination reduce karna aur accurate answers generate karna.

---

# Three Components of AI System

Har AI system ke 3 main components hote hain.

```
Input

↓

Model

↓

Output
```

In tino ko secure karna bahut important hai.

---

# AI Security Threats

## Prompt Injection

Attacker malicious prompt dekar model ko manipulate karta hai.

---

## Data Poisoning

Training data me harmful ya fake data add kar diya jata hai.

Result:

Wrong model behavior.

---

## Model Inversion

Attackers model se sensitive training information recover karne ki koshish karte hain.

---

# Security Best Practices

Generative AI applications me implement karo:

- Encryption
- Multi-Factor Authentication (MFA)
- Continuous Monitoring
- Security Policies
- Access Control

---

# Why Continuous Monitoring?

Continuous monitoring help karta hai:

- Threat Detection
- Performance Monitoring
- Security Compliance
- Risk Reduction

---

# Compliance

Organizations ko legal aur regulatory requirements follow karni hoti hain.

Examples:

- Data Privacy
- Security Standards
- Company Policies

---

# Important Exam Notes ⭐

Remember:

- AWS Benefits → Accessibility, Cost-Effectiveness, Faster Development.
- Transfer Learning → Existing model ko reuse karna.
- SageMaker JumpStart → Pre-built Models & Projects.
- CAF-AI → AI Adoption Framework.
- AWS AI Stack → Infrastructure → Models → Applications.
- AWS Nitro System → Secure EC2 Infrastructure.
- Inferentia → Model Inference.
- Trainium → Model Training.
- P4/P5/G5/G6 → GPU Instances.
- RAG → External knowledge retrieve karke better response deta hai.
- AI System → Input → Model → Output.
- Prompt Injection → Malicious prompts.
- Data Poisoning → Harmful training data.
- Model Inversion → Sensitive data recover karne ki attack.
- Security → Encryption + MFA + Continuous Monitoring.
--------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------------
# AWS AI Practitioner (AIF-C01)
# Domain 2 - Task Statement 2.3 (Lesson 2)
## AWS Generative AI Services, Pricing & Cost Optimization

---

# 📌 Pricing Models for LLMs

LLMs use karne ke mainly **2 pricing models** hote hain.

## 1. Self-Hosted Model

Apne infrastructure par LLM host karna.

Aap responsible hote ho:

- Compute Cost
- Storage
- Maintenance
- Security
- Scaling
- Model Updates

Kabhi-kabhi model ka **License Fee** bhi pay karna padta hai.

---

## 2. Pay-by-Token Model

Sirf jitne tokens process honge utna hi payment.

Formula:

```
Cost

=

Input Tokens

+

Output Tokens
```

Ye AWS aur bahut se AI providers ka common pricing model hai.

---

# Token-Based Pricing

Token = Information ki smallest processing unit.

Examples:

- Word
- Part of a Word
- Character
- Image Representation

Billing hoti hai:

- Input Tokens
- Output Tokens

Dono ke basis par.

---

# Benefits of Pay-by-Token

- Pay only for usage
- No infrastructure management
- Highly scalable
- Cost-efficient
- Easy to start

---

# Self-Hosting vs Pay-by-Token

| Self-Hosted | Pay-by-Token |
|-------------|--------------|
| Infrastructure required | No infrastructure |
| High upfront cost | Low initial cost |
| Maintenance required | Fully managed |
| Good for very large workloads | Good for most applications |
| User manages scaling | AWS manages scaling |

---

# AWS ML Stack

AWS ML ecosystem ko 3 layers me divide kiya ja sakta hai.

```
AI Services

↓

ML Services

↓

AWS Infrastructure
```

---

# AWS Infrastructure Layer

Foundation provide karta hai.

Includes:

- AWS Regions
- Availability Zones (AZs)
- Edge Locations

Benefits:

- High Availability
- Fault Tolerance
- Scalability

---

# High Availability

Application continuously available rehti hai,

even agar ek server fail ho jaye.

---

# Fault Tolerance

Agar ek component fail ho,

to dusra component automatically workload handle karta hai.

---

# AWS ML Services

Main Service:

## Amazon SageMaker

Use Cases:

- Build Models
- Train Models
- Fine-Tune Models
- Deploy Models

---

# AWS AI Services

Ready-to-use AI services.

Examples:

- Amazon Bedrock
- Amazon Rekognition
- Amazon Comprehend
- Amazon Textract

Developers bina ML expertise ke APIs use kar sakte hain.

---

# SageMaker JumpStart

JumpStart ek **Model Hub** hai.

Provides:

- Foundation Models
- Sample Notebooks
- Datasets
- Example Projects
- Fine-Tuning
- Deployment

Goal:

Generative AI projects ko jaldi production me lana.

---

# Cost Optimization for SageMaker

Best Practices:

- Correct GPU choose karo.
- Unused endpoints delete karo.
- Usage monitor karo.
- Pricing page check karo.

Ye unnecessary cost bachata hai.

---

# Amazon Bedrock

Amazon Bedrock ek **Fully Managed Generative AI Service** hai.

Features:

- Multiple Foundation Models
- API Access
- Fine-Tuning
- Model Evaluation
- Serverless Experience

Infrastructure manage karne ki zarurat nahi hoti.

---

# Foundation Models Available in Bedrock

Examples:

- Amazon Titan
- Cohere
- Stability AI
- Anthropic Claude
- Meta Llama *(availability may vary)*

Ek hi API se multiple models access kiye ja sakte hain.

---

# Amazon Titan

Amazon ka khud ka Foundation Model family.

Supports:

- Text Generation
- Embeddings
- Image Generation

Best for:

General-purpose Generative AI applications.

---

# Why Use Bedrock?

Benefits:

- No infrastructure management
- Pay-as-you-go
- Easy API integration
- Multiple Foundation Models
- Enterprise Security
- Scalable

---

# Model Evaluation in Bedrock

Bedrock help karta hai:

Different Foundation Models compare karne me.

Evaluate based on:

- Accuracy
- Response Quality
- Latency
- Cost

Best model choose karna easy ho jata hai.

---

# Playground

Playground ek experimentation environment hai.

Use Cases:

- Different prompts test karna.
- Multiple models compare karna.
- Inference parameters change karna.

Production deploy kiye bina testing kar sakte ho.

---

# Inference Parameters

Inference parameters response ko control karte hain.

Examples:

- Temperature
- Top-K
- Top-P
- Maximum Tokens

Different values

↓

Different outputs.

---

# PartyRock

PartyRock Amazon Bedrock par based learning platform hai.

Purpose:

Generative AI applications banana bina coding ke.

Examples:

- Playlist Generator
- Trivia Games
- Recipe Generator
- Story Generator

Learning aur experimentation ke liye useful hai.

---

# Why Most People Don't Train Their Own LLM?

Reasons:

- Extremely Expensive
- Huge Compute Required
- Massive Dataset Required
- Long Training Time
- Data Cleaning Required
- Complex Infrastructure

Isliye organizations mostly pre-trained Foundation Models use karti hain.

---

# Why Not Host Your Own Model?

Challenges:

- GPU Cost
- Storage Cost
- Maintenance
- Scaling
- Security
- Monitoring

Managed services usually better option hote hain.

---

# Vector Database

Generative AI me data store hota hai:

**Embeddings** ke form me.

Embedding

↓

Vector

↓

Vector Database

---

# Benefits of Vector Databases

- Fast Semantic Search
- Similarity Search
- Efficient Retrieval
- RAG Applications
- Scalable Storage

---

# AWS Advantages for Generative AI

AWS provide karta hai:

- Industry-leading Foundation Models
- Enterprise-grade Security
- Privacy Protection
- Scalability
- Easy Customization
- Cost Optimization
- Managed Infrastructure

---

# Important Exam Notes ⭐

Remember:

- LLM Pricing → Self-Hosted OR Pay-by-Token.
- Token-Based Pricing → Input + Output Tokens.
- Self-Hosting → High cost + Maintenance.
- Pay-by-Token → Pay only for usage.
- AWS ML Stack → Infrastructure → ML Services → AI Services.
- Regions + AZs → High Availability & Fault Tolerance.
- SageMaker → Build, Train, Fine-Tune & Deploy Models.
- SageMaker JumpStart → Model Hub + Quick Deployment.
- Delete Unused Endpoints → Cost Optimization.
- Amazon Bedrock → Fully Managed FM Service.
- Amazon Titan → AWS Foundation Model.
- Playground → Model Experimentation.
- PartyRock → No-code AI App Builder.
- Vector Database → Stores Embeddings.
- Embeddings → Numerical Vector Representation.
- RAG → Uses Vector Database for retrieving relevant information.
