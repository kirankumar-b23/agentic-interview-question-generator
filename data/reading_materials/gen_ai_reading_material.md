<iframe src="https://genairoadmap.niat.tech/" width="100%" height="580" frameborder="0" marginwidth="0" marginheight="0" scrolling="yes" style="border:1px solid #CCC; border-width:1px; margin-bottom:5px; max-width: 100%;" allowfullscreen></iframe>

# Generative AI Foundations



So far in this course we have covered the Generative AI Awareness Session, Generative AI Applications, the Generative AI Landscape, and the evolution of the ecosystem — from models to **Agents** and the pursuit of **AGI**. In this session, we go deeper into the technology that powers all of it: the **Large Language Model (LLM)**.

# 1. LLMs – The Brain Behind Generative AI

**Understanding with a Car Example**

We all know what a car is and how it works. But what is the most important component in a car? It's the **engine** — the core engine gives the power to the car, driving the wheels and determining its performance.

Similarly, when building a Generative AI application, the **Large Language Model (LLM)** acts like the powerful **engine**. Just as an engine powers a car, the LLM is the powerful engine behind most Generative AI applications.

## 1.1 Large Language Models (LLMs)

An LLM is the core part of Generative AI. It is an advanced type of AI model that is trained on vast amounts of text data to understand, generate, and process human language. It behaves like a **Super Intelligent Model**.

**Capabilities:**

- Text Generation
- Language Translation
- Summarization
- Language Understanding
- Reasoning

**Resources Required to Build an LLM:**

- **Compute:** CPU / GPU / TPU (Millions)
- **Memory:** Terabytes
- **Time & Cost:** Months of training, hundreds of crores
- **Datasets:** Peta Bytes
- **Research & Development:** Top-notch researchers, developers, and entrepreneurs

**Number of Parameters:**

The scale of an LLM is often described by its number of parameters, which spans a huge range:

- 1 Billion
- 4.5 Billion
- 125 Billion

### A High-Level Look

> When you give a prompt (Input) to an LLM, it processes your request and provides an Output — this is how text generation tools like chatbots or content creators work.

### Multimodal LLMs

> These are advanced models that can handle different types of data like text, images, audio, and video. Instead of just understanding and generating text, they can process input and generate output across multiple formats.

### Pre-Trained LLM Models

> Pre-trained LLM models — for example, **GPT-5.5** — are large language models that have already been trained by big companies on massive amounts of data. These models are ready to use, allowing small companies and individuals to build solutions without spending a lot of time, money, or resources on training their own models.

### Fine-Tuned LLM Models

> Fine-tuned models start from a pre-trained base and are further trained with specific context for specialized tasks or domains. In short: **Fine-Tuning = Adding Specific Context + a Pre-trained model.**

### Fine-Tuning a Pre-Trained Model

> For example, imagine an 8th-grade student who has already **passed** 8th-grade mathematics — that prior learning is the **pre-trained** knowledge. When the same student prepares specifically for the **9th-grade mathematics exam**, that focused, goal-based preparation is the **fine-tuning**. Similarly, LLMs are fine-tuned with additional data for targeted performance.

## 1.2 Open vs Closed Source Models

Models broadly fall into two categories. **Open source** models are publicly available and allow anyone to use, modify, and distribute them. **Closed source** models are not publicly accessible and are developed and maintained by organizations or companies.

| Model Type     | Open Source Models                                                        | Closed Source Models                                                        |
| -------------- | ------------------------------------------------------------------------- | --------------------------------------------------------------------------- |
| **Definition** | Publicly available; anyone can use, modify, and distribute the software.  | Not publicly accessible; developed and maintained by organizations/companies. |
| **Examples**   | **Llama 4**, **Mistral Large 3**, **Gemma 4** …and many more              | **Claude Opus 4.8**, **Gemini 3**, **GPT-5.5** …and many more               |

### Closed Source Models

**Pros:**

1. Easy to use (just sign up and start)
2. Regular updates and improvements
3. Better customer support

**Cons:**

1. Can be expensive for heavy usage
2. Privacy concerns (data goes to their servers)
3. Limited customization

### Open Source Models

**Pros:**

1. Free to use and modify
2. Complete control over the model
3. Privacy — run locally on your own computer

**Cons:**

1. Requires technical knowledge to set up
2. May need powerful hardware
3. No official customer support

## 1.3 The Open Source Community & Ecosystem

### Open Source AI Research & Model Developers

A growing set of organizations research and release open models for everyone to build on:

| Organization     | Description                                        |
| ---------------- | -------------------------------------------------- |
| **Meta**         | Releases state-of-the-art open models.             |
| **Mistral AI**   | Specializes in high-performance, open-weight LLMs. |
| **Hugging Face** | Leading hub for AI models, datasets, and tools.    |
| **Stability AI** | Focuses on open generative AI for images and text. |
| **DeepSeek**     | AI research in science, health, and reasoning.     |
| …many more       |                                                    |

### Open Source Model Hosting Platforms

Once built, models need to be hosted and shared. Some of the leading platforms are:

| Platform           | Description                                         |
| ------------------ | --------------------------------------------------- |
| **Hugging Face**   | The largest open-source AI model repository.        |
| **TensorFlow Hub** | Model repository for Google's TensorFlow ecosystem. |
| **PyTorch Hub**    | PyTorch-based model repository.                      |
| **Civit AI**       | Specializes in AI art models and LoRA sharing.      |
| …many more         |                                                     |

## 1.4 Hugging Face

Hugging Face is the AI community that is building the future — the platform where the machine learning community collaborates on models, datasets, and applications.

### GitHub vs Hugging Face

#### **GitHub**

- **Launched:** 2008
- **Monthly Visits:** ~462.4 million
- **Acquisition:** Acquired by Microsoft for $7.5B
- GitHub is a widely popular platform among developers worldwide, where software developers collaborate to build and share applications.

#### **Hugging Face**

- **Launched:** 2016
- **Monthly Visits:** ~37.9 million
- **Valuation:** ~$4 Billion
- Hugging Face is where the machine learning community collaborates on and shares models, datasets, and AI applications.

---

### Top Tech Companies

More than **50,000 companies** have deployed models on Hugging Face, making it a central platform where the community collaborates, gives feedback, and improves models together.

---

### What Hugging Face Contains

On Hugging Face you will find a massive, ever-growing collection of resources:

- **Models** — 2M+
- **Applications** — 1M+
- **Datasets** — 500K+

---

### Build Your Portfolio

Hugging Face also lets you share your work with the world and build your ML profile through:

- **Research Papers**
- **Models Built**
- **Applications**

---

### Accelerate Your ML

Hugging Face provides the compute and memory resources you need to accelerate your machine learning work:

- **CPU**
- **GPU**
- **TPU**
- **Memory**

---

### Using Hugging Face Models

We can use/run the Hugging Face models in different ways:

- Using Inference Providers
- Running Locally, etc.

---

### Using Inference Providers

- Hugging Face integrates with multiple inference providers (e.g., Together AI, Replicate, fal.ai, Cohere, etc.).
- The model runs on the provider's cloud servers.

---

### Hands-on: Meta Llama Model

<details>

<summary>Meta Llama 3.1 8B Instruct</summary> <a href="https://huggingface.co/meta-llama/Llama-3.1-8B-Instruct" target="_blank">huggingface.co/meta-llama/Llama-3.1-8B-Instruct</a>
<br>
</details>

---

### Hugging Face vs GitHub — Who Uses What?

- **GitHub** → built for **programmers** collaborating on software.
- **Hugging Face** → open to **everyone**, including non-programmers, to discover, use, and share AI models.

# Exploring Gen AI Capabilities

In the previous unit, we learned how Gen AI can help us talk better, be more creative, learn new things, and solve problems in daily life. In this unit, we will explore useful Gen AI capabilities like searching the internet for the latest information, doing deep research from many websites, talking to AI using our voice interaction, getting help by sharing our screen, and choosing the right AI model for tasks like quick answers, writing code, or solving hard problems.

> *"Think of a task or problem you faced recently where you think Gen AI could have been helpful"*

> *"Let's explore the most practical and powerful capabilities we can start using immediately"*

# 1. Gen AI Capabilities

## 1.1 Search (Web Browsing)

### 1.1.1 Real-Time Information Access
Search (Web Browsing) is the process where AI models access current information from the internet to provide up-to-date responses.

**Tools:**

- **ChatGPT** 
- **Claude** 
- **Gemini**

**Search-ChatGPT**
ChatGPT searches for trending Instagram challenges and provides current information.


<details> <summary>**Trending Reels**</summary> 

>**Prompt**

>```
>What are the trending Instagram reel challenges right now?
>```

</details>

<details> <summary>**Local Recommendations**</summary>

>**Prompt**

>```
>Show me the best restaurants near me
>```

</details>


<details> <summary>**Top AI Tools**</summary>

>**Prompt**

>```
>What are the top 3 AI tools launched this week?
>```

</details>


<details> <summary>**Financial Updates**</summary>

>**Prompt**

>```
>How has Apple's stock performed over the last week?
>```

</details>

The LLM response will contain inline citations, and we can hover over the citations to learn more


### Using Across Domains

- **Agriculture**: To find crop care tips, pest control methods, and weather forecasts
- **Education**: For the latest course materials or tutorial videos on specific subjects
- **Sports**: For live scores, player stats, and upcoming match schedules
- **Fashion**: For the latest trends, and brand comparisons in online stores


## 1.2 Deep Research

### 1.2.1 Comprehensive Analysis
For complex decisions or in-depth understanding, we need comprehensive research that explores multiple sources and presents a complete picture

Designed to perform in-depth, multi-step research using data from the web

- **Search** → **Extract** → **Analyze** → **Summarize**

### **Deep Research as a Team of Researchers**

- Reading Through Webpages
- Analyzing Information
- Comparing Different Viewpoints

It is great for people who need to find detailed and accurate information from various websites


**Example:** 

- **Buying a Laptop**

Let’s say you want to buy a laptop

instead of spending hours comparing specs across: 

- Different Websites
- Reading Reviews
- Checking Prices

We can use deep research feature

<details> <summary>**Deep Research for Purchasing**</summary>
>**Prompt**

>```
>I am planning to buy a new laptop and need a detailed comparison to make the right decision. My budget is ₹60,000 to ₹80,000, and I will mainly use it for web development and occasional video editing. Please suggest 3–5 laptops that are best suited for this use case
>```

</details>


<details> <summary>**Deep Research for Career Planning**</summary>

>**Prompt**

>```
>I am a computer science student interested in AI/ML careers. Can you do deep research on: 1. The current job market for AI engineers in India 2. Skills and certifications most in demand 3. Average starting salaries 4. Growth prospects over the next 5 years 5. Companies hiring the most AI engineers in India
>```

</details>

Deep research typically completes a query within 5 to 30 minutes, depending on its complexity

<MultiLineNote>
There will be a daily limit for using the search and deep research features
Try using Claude, Gemini, and Llama
</MultiLineNote>



### 1.2.2 Use Cases for Deep Research

Deep Research capabilities extend across major decision-making scenarios.


- **Major Purchase Decisions**
- **Academic Research**  
- **Career Planning**
- **Investment Research**
- **Travel Planning**



## 1.3 Voice Input and Output

### 1.3.1 Voice Input
Modern LLMs can understand natural speech and respond with human-like voices, making interactions more intuitive and accessible

They can accept voice input, allowing us to speak directly, with our speech being converted into text for processing



- **Speech** → **Text** → **Processing** → **Voice Response**


<details> <summary>**Voice to Text**</summary>

>**Prompt**

>```
>Hey, Can you suggest the best places to visit in India?
>```

</details>


<MultiLineNote>
There will be a daily limit for using the deep research and advanced voice mode features
Try using Claude, Gemini, and Llama

</MultiLineNote>

<details> <summary>**Advanced Voice Mode**</summary>

>**Prompt**

>```
>Act as my best friend who cares about me a lot. Let’s role-play a conversation
>```

</details>

<details> <summary>**Practice Speaking and Listening**</summary>

>**Prompt**

>```
>Can you teach me English by having a conversation with me? Please ask me questions in between and correct my mistakes
>```

</details>

<details> <summary>**Speaking Practice**</summary>

>**Prompt**

>```
>I need to practice my presentation speech for tomorrow. Can you listen and give me feedback? My topic is Generative AI
>```

</details>

<details> <summary>**Preparing for Interview(mock interview)**</summary>

>**Prompt**

>```
>Hey, I want to prepare for an AI Engineer fresher Role? Can we have a mock interview?
>```

</details>

### Chat GPT Voice Mode
During a voice chat, we can ask ChatGPT to search for something and it will provide us with fast, timely answers


## 1.4 Screen Sharing Capability


### 1.4.1 Screen Sharing Capability
We can also share the screen and ask questions. This feature allows LLMs to see what’s on your screen

**Use Cases:**

- **Code Debugging and Review**
- **Filling Complex Forms**
- **Resume/Document Review**

Screen sharing is currently in the experimental phase within ChatGPT's Advanced Voice Mode

Let’s use the Google AI Studio’s screen share feature

**Google AI Studio** is a platform where we can access and experiment with Google's AI models, including Gemini

**Example**: Let’s say you are creating or editing a PPT for your project presentation, and you don't know how to insert an image


<details> <summary>**While Creating PPT**</summary>

>**Prompt**

>```
>Hey, I am working on this slide. Can you guide me with the steps on on how to insert an image on it?
>```

</details>

<details> <summary>**Debugging Code**</summary>

>**Prompt**

>```
>I am getting an error in my Python code. Can you look at my screen and help me figure out what's wrong?
>```

</details>


<details> <summary>**Job Application**</summary>
>**Prompt**

>```
>What does 'Stream' mean here? Should I select 'IT' or 'Engineering'? I want to apply for the AI Engineer role, and I am from CSE
>```

</details>


## 1.5 Understanding Different AI Models

Just as we would not use a hammer for every task in a toolbox, different types of AI models are optimized for different kinds of tasks

### 1.5.1 Most Common Model Categories

Different AI models are optimized for specific tasks, similar to having different tools in a toolbox for different purposes.

**Model Types:**

- **Reasoning Models**
- **Flash Models**
- **Coding Specialists**
- **General Purpose**
- **Cost-Efficient**
- **Small Language Models**


### 1.5.2 Reasoning Models
Reasoning models are helpful in handling complex logical tasks through step-by-step thinking processes

- Breaking down multi-step problems into smaller components
- Following logical chains of thought
- Supporting deeper analysis and more thorough consideration of problems


<details>
<summary>**Example**</summary> 

```
What is the next number in the series? 2, 6, 12, 20, 30, ___?
```

</details>



### 1.5.3 Flash Models
Flash models (sometimes called "fast" models) are optimized for speed and efficiency, rather than deep reasoning

**Capabilities:**

- Quick responses to routine queries
- Efficient processing of simple tasks
- Lower computational requirements
- High-volume interaction handling

<details>
<summary>**Example**</summary> 

```
Create a simple weekly workout plan for a beginner
```
</details>

### Models
**Specialized in Coding**

- Anthropic Claude Opus 4
- OpenAI GPT-4.1
- DeepSeek-Coder-V2
- Meta Code Llama

**General Purpose: ** 
**For day-to-day Use**

- GPT-4o, 
- GPT-4o-mini
- Claude Sonnet 4
- Gemini 2.5 Flash
- Llama 4 Maverick

**Cost Efficient**

- DeepSeek(all models)
- Llama 4
- Gemma 3n
- Phi-3-mini

**Choosing an LLM**

Make sure you choose the ‘best’ LLM depending on your needs..!"

# Productivity Power Up with AI Tools

In this unit, we will learn how **AI tools** can significantly improve productivity. We’ll see how they help in tasks such as creating presentations, understanding complex code, and automating everyday processes.

## Let’s Explore the Tools We Are Going to Learn
- **Gamma AI**: A tool to create professional presentations in minutes.
- **DeepWiki**: Understand any GitHub repository by generating wiki-style documentation.
- **ChatGPT**: Uncover hidden features for automation and customization.

# 1. Gamma AI: Create Professional Presentations in Minutes

Creating presentations is time-consuming: brainstorming ideas, finding images, formatting slides, and ensuring a professional look.

- **Gamma AI** turns your ideas into professional slides in minutes, automating design, layout, and visuals, allowing you to focus on content

## How to Use Gamma AI

<details>
<summary><strong>Step 1: Create an Account</strong></summary>

- Visit <a href="https://gamma.app/" target="_blank">Gamma AI</a>.
- Create an account using email or Google account.
- Get free credits (usually 400 credits) to start.
</details>

<details>
<summary><strong>Step 2: Generate Your First Presentation</strong></summary>
<br>
Choose from three options:

- `GENERATE`: Let AI create from a prompt.
- `IMPORT`: Upload existing content.
- `PASTE`: Copy-paste your text content.

If you choose **"Generate"**, here's how to write effective prompts:

```
Create a presentation on Generative AI. Keep it engaging and beginner-friendly.
```

Gamma generates your presentation in 2-3 minutes.
</details>

<details>
<summary><strong>Step 3: Customization</strong></summary>

- Click on any slide to edit text, images, or layout.
- Use **Redesign** to try different visual styles.
- Add your own images by clicking image placeholders.
- Adjust colors using the theme selector.
</details>

## Advantages
- **Time-Saving**:Reduces hours presentation creation into minutes
- **Professional Design**:AI creates visually appealing layouts without design skills
- **Content Focused**: Spend time on ideas, not formatting

## Similar Tools
Gamma is powerful, but it’s not the only option. Depending on comfort, there are other tools that can also be tried

- **Beautiful.ai**
- **Sendsteps.ai**
- **Canva**

# 2. DeepWiki: Simplifying GitHub Repos into Learning Materials

Have you ever struggled to understand complex code in a GitHub repo?

- **DeepWiki** helps you understand complex code in GitHub repos without proper documentation can be overwhelming
- It turns complex GitHub projects into easy-to-follow tutorials, helping you understand the code better

## How to Use DeepWiki

<details>
<summary><strong>Step 1: Visit DeepWiki</strong></summary>

- Go to <a href="https://www.deepwiki.com" target="_blank">deepwiki.com</a>.
</details>

<details>
<summary><strong>Step 2: Converting Repository to Wiki</strong></summary>

- Paste the complete GitHub URL.
- Ensure the repository is **public**.
- Click **"Enter"**.
</details>

<details>
<summary><strong>Step 3: Learn from Generated Wiki</strong></summary>

- Read `architecture diagrams` that show how the parts of the project connect.
- Browse `chapter-style pages` explaining the file structure and main components.
- Follow `links to the exact source code` behind each explanation.
- Ask questions in plain English (and get answers grounded in the code).
</details>

## Advantages

- **Instant Code Understanding**: Converts complex repositories into beginner-friendly tutorials.
- **Visual Learning**: Generates architecture diagrams and links to source code.
- **Time-Saving**: No need to spend hours figuring out code structure.

# 3. ChatGPT's Hidden Productivity Features

Most students use ChatGPT for basic questions, while ChatGPT's true potential remains hidden below

## Features 
1. Custom GPTs
2. Agent Mode (ChatGPT Pro)

### 1. Custom GPTs

ChatGPT allows you to access thousands of specialized GPTs created by the community for specific tasks

- #### **How to Access GPTs**

     - Open ChatGPT → Explore GPTs (sidebar) → search → Start Chat

- **Hands On Scholar GPT**
    Find and explore over 200 million research papers, patents, and books to discover new ideas and learn more about any topic
    
    ```
    Find the latest research about AI
    ```

- **Popular Student-Focused GPTs**
    - Scholar GPT: Find and explore over 200 million research papers, patents, and books.
    - Math Solver: Advanced mathematical problem solving.
    - Code Tutor: Programming guidance and explanations.
    - Essay Writer: Academic writing assistance.

<MultiLineQuickTip>
You can also create Custom GPTs with a ChatGPT Plus or Pro account
</MultiLineQuickTip>

### 2. Agent Mode (ChatGPT Pro)

- **What is Agent Mode?**
Agent Mode turns ChatGPT into a smart assistant that can work on its own to finish complex tasks that have multiple steps

- **Examples**
    
    User: ``` Hey AI, I have an interview in Mumbai tomorrow. Handle everything for me
    ```
    
    Agent : ```Hey, Sure Your flight and hotel is booked. Here are the details```
    
    Within minutes, your flight is booked, hotel reserved
    
    
    - #### Booking a Flight
     
    AI agent opens a browser, searches for flights on Paytm, compares prices, and books a ticket automatically.
    
    Some interaction was required for flight preferences and payment details.
    
    - ####Ordering Groceries
     
    
    AI Agents can order groceries, add items to the cart, complete the purchase, and confirm the order automatically.
    
    
      
    <MultiLineNote>
    Agent mode is currently available on Pro, Plus, Team, Enterprise, and Edu plans
    </MultiLineNote>

- **Enable Agent Mode (ChatGPT Pro)**

    Go to Tools and SelectAgent Mode
    
    <details>
      <summary>Sample Resume</summary>
      <a href="https://s3.ap-south-1.amazonaws.com/new-assets.ccbp.in/frontend/loading-data/niat-course-projects/sample_resume.pdf" target="_blank">
     Open Sample Resume (PDF)
     </a>
      </details>

     <details>
      <summary>Prompt</summary>
      
      ```
    Find AI/ML internships posted in the last 7 days, remote or in India, suitable for a 1st-year BTech student. Summarize top 5 roles with apply links. Then, help me write and personalize cover letters for each using my uploaded resume
    ```
      </details>
    
    ---

# Introduction 

In the previous unit, we explored how AI tools can enhance productivity, from creating presentations to understanding complex code and automating tasks.
In this unit, we dive into prompt engineering, the art of crafting clear and detailed prompts to help large language models (LLMs) generate accurate and high-quality answers. We’ll cover the fundamentals, techniques, and best practices for effective prompt creation.


# Prompt Engineering Fundamentals

Have you ever asked an LLM a question and received a confusing or unhelpful response?

<MultiLineNote>Better Prompt… Better Results..!</MultiLineNote>


The natural language text, which describes the task that an LLM should perform, is called a prompt

## Examples

<details>
<summary><strong>Basic Prompt:</strong></summary>

```
What is generative AI?
```
</details>

<details>
<summary><strong>Better Prompt:</strong></summary>

```
I'm a first-year B.Tech student. Can you explain what generative AI is in simple terms, with examples of how it's used in apps like ChatGPT?
```

</details>

---

<details>
<summary><strong>Basic Prompt:</strong></summary>

```
How to prepare for exams?
```

</details>

<details>
<summary><strong>Better Prompt:</strong></summary>

```
I'm a first-year B.Tech student with exams in two weeks. Can you recommend a study plan that includes revision strategies, breaks, and how to handle difficult subjects?
```

</details>
<MultiLineQuickTip>If you observe carefully, the LLM response depends on how the question is asked. The clearer and more detailed your prompt is, the better the model output will be.</MultiLineQuickTip>
**Better Prompts Lead To Better Results!**

The clearer and more detailed your prompt is, the better the model output will be

# 1. Prompt Engineering
Prompt engineering is the art of creating prompts that help an LLM generate more accurate and higher-quality answers

**Think of it like this**

- If an LLM is like a highly knowledgeable intern on their first day
- Prompt engineering is the skill of giving that intern clear, detailed instructions 

## Why Prompt Engineering?

- **Better results**: More accurate, relevant, and useful responses.
- **Consistency**: Well-engineered prompts produce reliable results each time.
- **Saves time**: Get what you need in fewer iterations.
- **Avoid confusion**: A clear prompt prevents the model from making incorrect assumptions.

## Be Clear and Direct

- Think of an LLM like a new intern
- It doesn't know what to do unless you explain it.
- It needs detailed instructions to perform correctly.

The more clearly and specifically you explain what you want, the better and more accurate the response will be.

<details>
<summary><strong>Basic Prompt:</strong></summary>

```
Write a resume
```
</details>

<details>
<summary><strong>Better Prompt:</strong></summary>

```
Can you help me create a professional resume for a BTech CSE student? Include sections like personal details, education, skills, internships, projects, and achievements. Please provide tips for each section to make the resume stand out to potential employers.
```
</details>

# 3. Basic Prompt Structure

## The RCATF Framework

* **Role**: Defines the persona of the AI.  
* **Context**: Provides the background and limitations.  
* **Action/Task**: Specifies the task or question.  
* **Format**: Specifies the format of the output.  
* **Tone**: Defines the style or voice the AI should use.

## Role

- It is sometimes important to prompt the LLM to take on a specific role.  
- This technique is known as **role prompting**.  
- The more detail you provide about the role and context, the better the results.  
- Priming an LLM with a specific role can enhance its performance across various tasks, from writing to coding to summarizing.  
- It's like how humans can sometimes be helped when told to "think like a ______".  
- Role prompting can also change the style, tone, and manner of the LLM’s response.

<details>
<summary><strong>Examples</strong></summary>
- You are a professional chef with 20 years of experience in Italian cuisine.
- Act like a stand-up comedian from New York.
- You are a senior software engineer specializing in frontend development.

</details>
<details>
<summary><strong>Prompt</strong></summary>

```
Act as an experienced travel consultant who specializes in budget-friendly trips and has personally visited over 50 destinations."
```
</details>

## Context

- Context tells the LLM who it's helping, what the situation is, and any limitations.  
- Good context helps the LLM understand your specific needs.

<details>
<summary><strong>Examples</strong></summary>


- **Personal situation**: "I'm planning a trip to Japan."
- **Audience information**: "This is for high school students."
- **Project details**: "We're launching a new product next month."
- **Constraints**: "We have a limited budget."
- **Prior knowledge**: "I have no experience with coding."
</details>

<details>
<summary><strong>Prompt</strong></summary>

```
Role: Act as an experienced travel consultant who specializes in budget-friendly trips and has personally visited over 50 destinations."

Context: I'm a 22-year-old college student planning my first solo trip. I have a budget of 20,000, 10 days to travel in June, and I'm interested in both outdoor activities and experiencing local culture. I'm somewhat adventurous but also concerned about safety as a solo traveler.
```

</details>

## Action/Task

- The specific action or task you want the LLM to perform.  
- This is the "verb" of your prompt – the specific action you want the LLM to take.

<details>
<summary><strong>Examples</strong></summary>

- **Explain/teach**: "Explain Generative AI."
- **Create/generate**: "Create a marketing plan."
- **Analyze/evaluate**: "Analyze this paragraph."
- **Summarize**: "Summarize this research paper."
- **Compare/contrast**: "Compare these two approaches."
- **Brainstorm**: "Brainstorm names for my startup."
</details>

<details>
<summary><strong>Prompt</strong></summary>

```
Role: Act as an experienced travel consultant who specializes in budget-friendly trips and has personally visited over 50 destinations."

Context: I'm a 22-year-old college student planning my first solo trip. I have a budget of 20,000, 10 days to travel in June, and I'm interested in both outdoor activities and experiencing local culture. I'm somewhat adventurous but also concerned about safety as a solo traveler.

Action: Recommend 2 specific destinations that would be ideal for my situation, and for each destination, suggest a 10-day itinerary that balances cultural experiences, outdoor activities, and relaxation.
```

</details>

## Format
- Format tells the LLM how you want your answer organized and presented.

<details>
<summary><strong>Examples</strong></summary>

- Bullet points or numbered lists
- Table or chart
- Step-by-step guide
- FAQ style (question and answer)
- Timeline
- Markdown formatting with headers and subheaders
</details>

<details>
<summary><strong>Prompt</strong></summary>

```
Role: Act as an experienced travel consultant who specializes in budget-friendly trips and has personally visited over 50 destinations."

Context: I'm a 22-year-old college student planning my first solo trip. I have a budget of 20,000, 10 days to travel in June, and I'm interested in both outdoor activities and experiencing local culture. I'm somewhat adventurous but also concerned about safety as a solo traveler.

Action: Recommend 2 specific destinations that would be ideal for my situation, and for each destination, suggest a 10-day itinerary that balances cultural experiences, outdoor activities, and relaxation.

Format: For each destination, create a section that includes:
A short overview (3–5 sentences)
An estimated cost breakdown (accommodation, food, activities, transport)
Safety tips for solo travelers

Then provide a day-by-day itinerary in table format with columns for:
Day #
Morning activity
Afternoon activity
Evening activity
Accommodation
Finally, end with a pros and cons list for each destination
```
</details>


## Tone

The style, voice, or emotional quality you want the LLM to use in its response. This affects how the message feels to the reader.

<details>
<summary><strong>Examples</strong></summary>

- Formal or academic
- Friendly and conversational
- Encouraging and supportive
- Direct and concise
- Enthusiastic and energetic
- Cautious and balanced
- Simple and easy to understand

</details>
<details>
<summary><strong>Prompt</strong></summary>

```
Role: Act as an experienced travel consultant who specializes in budget-friendly trips and has personally visited over 50 destinations."

Context: I'm a 22-year-old college student planning my first solo trip. I have a budget of 20,000, 10 days to travel in June, and I'm interested in both outdoor activities and experiencing local culture. I'm somewhat adventurous but also concerned about safety as a solo traveler.

Action: Recommend 2 specific destinations that would be ideal for my situation, and for each destination, suggest a 10-day itinerary that balances cultural experiences, outdoor activities, and relaxation.

Format: For each destination, create a section that includes:
A short overview (3–5 sentences)
An estimated cost breakdown (accommodation, food, activities, transport)
Safety tips for solo travelers


Then provide a day-by-day itinerary in table format with columns for:
Day #
Morning activity
Afternoon activity
Evening activity
Accommodation
Finally, end with a pros and cons list for each destination

Tone: Include some humor where appropriate, and write as if you're a slightly older friend who wants to make sure I have an amazing but safe experience. Use casual language but don't skimp on important details.
```
</details>


# Example Prompt Templates
<details>
<summary><strong>Interview Preparation</strong></summary>

```
Template: "You're an experienced career counselor. I have an upcoming {{INTERVIEW_TYPE}} interview for a {{JOB_ROLE}} position. Provide me with 8-10 targeted practice questions I should prepare for, along with strategic tips for answering them effectively. Present this as a clear study guide with practical examples I can practice."
Inputs:
{{INTERVIEW_TYPE}}: "technical" / "behavioral" / "panel" / "phone screening" / "final round"
{{JOB_ROLE}}: "software engineer" / "marketing manager" / "data analyst" / "sales representative" / "project manager”

```
</details>


<details>
<summary><strong>Summarizing an Article</strong></summary>

```
Template: "You're a research assistant skilled at distilling complex information. I need to quickly understand the key insights from {{ARTICLE_TOPIC}}. Read through the content and create a concise summary that captures the main arguments, supporting evidence, and conclusions. Format this as bullet points with the most important takeaways first, using clear and objective language."
Inputs:
{{ARTICLE_TOPIC}}: "climate change research paper" / "new technology trends report" / "healthcare policy analysis" / "market research study" / "historical analysis piece"

```
</details>

# Tricks and Tips
## Separating Data from Instructions

- Instead of writing a new prompt each time, 
you can create a reusable prompt template and 
that can be reused with different data each time
- This is especially useful when you need 
the LLM to perform the same task repeatedly but with different input data

<details>
<summary><strong>Simple Template</strong></summary>

```
I will tell you the name of an animal. Please respond with the sound that animal makes. {{ANIMAL}}

```
</details>

## Why Separate Data from Instructions?

- **Reusability**: Create once, use multiple times with different data.
- **Consistency**: Same task structure ensures consistent results.
- **Clarity**: Keeps instructions separate from variable content.

<details>
<summary><strong>Example</strong></summary>

```
Template: "Explain {{CONCEPT}} at a {{LEVEL}} level with examples."
Inputs:
{{CONCEPT}}: "recursion in programming" / "object-oriented programming" / "Ohm’s Law" 
{{LEVEL}}: "high school" / "first year btech student" / "intermediate" / "advanced"

```

```
Final Prompt: "Explain recursion in programming at a high school level with examples."
```
</details>

##Additional Exploration

- **OpenAI Examples**:  
  [OpenAI Documentation Examples](https://platform.openai.com/docs/examples)  
  [OpenAI Cookbook](https://cookbook.openai.com/)

- **For Cross-Platform Exploration**:  
  [Google Cloud Vertex AI Prompt Gallery](https://cloud.google.com/vertex-ai/generative-ai/docs/prompt-gallery)

- **Additional Prompt Resources**:  
  [Microsoft Prompts for Education - Students](https://github.com/microsoft/prompts-for-edu/tree/main/Students/Prompts)  
  [OpenAI Examples](https://platform.openai.com/docs/examples)  
  [Google Cloud Vertex AI Prompt Gallery](https://cloud.google.com/vertex-ai/generative-ai/docs/prompt-gallery)  
  [Microsoft Prompts for Education - Students (GitHub)](https://github.com/microsoft/prompts-for-edu/tree/main/Students/Prompts)

---

# Building Social Media Content Automation Workflow | Part 1

In the previous unit, we learned about **prompt engineering** and how to create clear prompts that help AI give better and more accurate answers. In this unit, we will focus on **AI workflows**, which are automated steps that use AI to complete tasks like creating content, analyzing data, and executing tasks automatically .

---

Have you ever spent too much time posting on social media about your learning progress/edu/career updates?(writing explanations, adding tech hashtags,  formatting, posting, etc)

What if you had a system that could handle all of this stuff automatically?

# AI Workflows
AI workflows are predefined sequences of steps that use artificial intelligence to complete tasks automatically

## Automated Workflow

An automated workflow typically follows the same structure:

- **Input**: The starting point where data or a trigger enters the system.
- **Tasks**: Steps performed in sequence (e.g., Task 1, Task 2, Task 3…).
- **Output**: The final product or result.

While some tasks may still require human involvement, particularly when judgment or approval is needed, the real efficiency boost occurs when AI handles repetitive middle steps. These are the tasks where humans usually waste time.

**Simple Flow**  

- **Task 1**: Human setup (e.g., upload a file, enter info)  
- **Task 2**: AI handles repetitive work (summarize, write, format)  
- **Task 3+**: Automatic follow-ups (approval, posting) → **Output**  

You don’t need AI to do everything. You just place it in the right steps to save the most time.

### Example: AI-Powered Social Media Content Automation

In an AI-powered workflow, content from an article is automatically summarized and adapted for social media posts. Here’s how the process works:

- **Listing the Articles**: Identifying content to be summarized.
- **Summarization**: Condensing articles into key points.
- **Generate Platform-Specific Content**: Tailoring content for specific social media platforms.
- **Auto-Post to Social Media**: Automatically posting the content on social media.

Once set up, it’s a one-click process.

## Workflow vs Manual Process

- ### Manual Process
    Involves reading articles, writing posts, creating different versions for various platforms, and manually posting them.
    
**Read Article Manually ** →  **Write LinkedIn Post** →  **Create Instagram Post** →  **Create Twitter Version** → **Post on All Platforms**
    
    Time Taken: **30-45** minutes per article.

- ### AI Workflow Process
    Involves adding a link to an article in a Google Sheet, which then triggers the workflow in n8n to create content suitable for multiple platforms and post it.
    
  **Add Article to Sheet** →  **Auto-generate Content** → **Post Everywhere Simultaneously** →  **Send Confirmations**
    
    Time Taken: Less than **2 minutes** of human effort.

## Applications
<details>
<summary><strong>Customer Service</strong></summary><br>

We've all experienced customer service where we get an instant reply — almost like someone was waiting for our message. Chances are, that "someone" was AI.

Here’s how it works:
1. A customer sends a query.
2. The system routes it to the right department (sales, support, billing) automatically.
3. If it’s a common question, AI sends a personalized reply immediately.
4. If follow-up is needed, the system schedules a call or raises a ticket.

Tools like **Zendesk**, **Atlassian**, and **HubSpot** already use AI to handle these tasks at scale, allowing support teams to focus on complex issues that need a human touch.

</details>

<details>
<summary><strong>Social Media Content Creation & Scheduling</strong></summary>
Managing content for a brand, blog, or personal profile can feel never-ending with the need for tailored posts on different platforms. An AI workflow can help streamline this by:

1. **Pulling Content**: Automatically pulling content from your blog or event calendar.
2. **Generating Captions**: Crafting platform-specific captions — LinkedIn gets a professional tone, Instagram gets catchy lines, Twitter gets short, punchy text.
3. **Creating Visuals**: generate simple visuals.
4. **Scheduling Posts**: Automatically scheduling posts across all platforms.
5. **Tracking Engagement**: Monitoring likes, shares, and comments to analyze performance and get tips on what’s working.

This means you can have the same system creating content, learning what works, and continuously improving — essentially giving you a smart, full-time social media team powered by AI workflows.

</details>

<details>
<summary><strong>E-Commerce Operations</strong></summary>

In e-commerce, like during a big Walmart sale, millions of orders come in at once. AI workflows keep things running smoothly by:

1. **New Order**: Order is received.
2. **Inventory Update**: Inventory updates automatically — no manual counting.
3. **Shipping Label**: Generated instantly based on the updated inventory.
4. **Confirmation**: Customer receives an email or SMS confirmation immediately.

Without automation, Walmart would need a huge team working around the clock. With AI workflows, the entire process happens at machine speed with minimal delay.

</details>

## Key Aspects of AI Workflows

1. **Predefined Paths**  
   The steps are fixed and follow the exact sequence you’ve set. No deviations unless you change them.

2. **Human Decision-Making**  
   If the AI output isn’t quite right, we step in. We adjust prompts, tweak steps, or give it feedback so it learns.
   
---

## Using n8n
- n8n is a workflow automation platform that enables users to automate tasks with ease
- It also allows us to connect with popular services like Google Sheets, Slack, Twitter, GitHub, and hundreds more

# Building Blocks

### Nodes
Each step in the workflow is represented by a node that performs specific actions such as retrieving, transforming, or sending data

Nodes You Might See in Workflows

- **Chat Trigger**: This starts the workflow when a user interacts in a chat or sends a command.

- **Social Media Nodes**: These manage and interact with platforms like LinkedIn, Twitter, Instagram.

- **SplitInBatches**: Useful when you have a large set of data and need to break it into smaller, manageable chunks for processing.

- **Google Sheets Trigger**: Reads from and writes data to Google Sheets automatically.  
  *Example*: Adding a new row to a sheet could trigger an entire workflow.

- **Slack Node**: Sends messages or interacts with your Slack workspace.

- **HTTP Request Node**: Allows n8n to talk to almost any web service that has an API.

### Connections
A connection establishes a link between nodes to route data through the workflow.


# Building AI-Powered Social Media Content Automation Workflow | Part 2


## Step-by-Step Guide

<details>
<summary><strong>Add Google Sheets Trigger</strong></summary>

<a href="https://learning.ccbp.in/course?c_id=d8360c96-9d99-4614-b1da-8f3a26ee57df&s_id=b6d8e5ed-7734-4324-add0-2edc5accefbb&t_id=31bf8d17-9d87-41fa-8d3a-b1b6250ccfac" target="_blank">Refer the Steps Present in the Unit</a>  


<details>
<summary><strong> Summarize the Article Using Gemini Chat Model</strong></summary>

- Add a new node → **Basic LLM Chain** 
- Name it as `Summarize News Article`
- Select `Define below`  
- Add **prompt** 
    
```
   System: "You are a social media strategist with expertise in content adaptation"

    User: "Analyze this article and create a summary that:
    1. Captures the 3 most important insights
    2. Includes any actionable advice or tips
    3. Maintains the original tone and perspective
    4. Highlights implications for the target audience
    5. Stays under 200 words for social media adaptation
    
    Article: {{$json.text}}

    
 ```
 
- Click on the `+` for the Basic LLM Model to select a model  
- Choose `Google Gemini Chat Model`  
- Click `Create New Credential`  
- Go to `API key` from <a href="https://aistudio.google.com/app/apikey" target="_blank">Google AI Studio</a>  
- Sign in with your Google account  
- Click `Create API key`  
- Copy the key and keep it safe  

</details>

<details>
<summary><strong>LLM Chain Node for Generating the LinkedIn Post</strong></summary><br>

- Add Another **Basic LLM Chain** Node
- Name it as `Generate LinkedIn Post Content`
- Select `Define below`  
- Add **prompt**

```
Assume the role of an industry expert and draft a LinkedIn post discussing key points from a news article relevant to artificial intelligence. The post should provide insightful analysis, connect with current industry trends, and encourage professional engagement or discussion. Highlight any notable implications for the industry. Since LinkedIn supports detailed posts, ensure it is informative and structured. Include a professional call to action. Here's a summary of the article: {ADD PREVIOUS NODE’S OUTPUT}

```

- Search and Add `Google Gemini Chat Model` 
- select the account which is already saved
- Connect it to the `Summarize News Article` node's output

</details>



<details>
<summary><strong>LinkedIn Node Configuration</strong></summary><br>

- Add `LinkedIn Node` to the `Generate LinkedIn Post Content`
- Name it as `Post to LinkedIn`
- create new credentials 
Go to <a href="https://www.linkedin.com/developers/apps/new" target="_blank">LinkedIn Developer Apps</a>  
- Enter an `App Name` (e.g., `n8n_post`)  
- In the `LinkedIn Page` field, search for `NIAT` and select the first option  
- Upload a `logo` of NIAT  
- Check the box → `I have read and agree to these terms`  
- Click on `Create App`  

- After app creation, the `Products tab` opens. Enable the required APIs:  
  - *Share on LinkedIn*  
  - *Sign In with LinkedIn using OpenID Connect*  

#### Setup Authentication

- Navigate to the `Auth tab`  
- Click `Add Redirect URL` → Paste the `OAuth Redirect URL` from n8n  
- Copy the `Client ID` → Paste it in n8n credentials  
- Copy the `Primary Client Secret` → Paste it in n8n credentials  
- Click `Create My Account` and complete `Sign In`  
- Connection should now be successful  

#### Final Steps in LinkedIn Node

- In the `LinkedIn Node parameters`, click `Person name or id` 
- Select the appropriate `Name or ID`  

</details>


<details>
<summary><strong>Auto-Post to Social Media</strong></summary>
- Automatically post the generated content to the respective social media platforms.

- #### Auto-Post to LinkedIn

    - Add LinkedIn Node
    - Select `Create a Post`
    - Authenticate Using Your LinkedIn Credentials
    - Select Username and Fill in the Text to Be Posted
    - Execute the workflow
    
    <MultiLineNote>Save and Reload the workflow after connected to linkedIn</MultiLineNote>



</details>

---

## Workflow Testing

<details>
<summary><strong>Trigger Testing</strong></summary>
- Add test article to Google Sheet  
- Execute the workflow  
- Check data passes between nodes  
</details>
<details>
<summary><strong>Content Quality Testing</strong></summary>
- Review AI-generated summaries  
- Verify platform-specific adaptations  
- Check character limits and formatting  
</details>
<details>
<summary><strong>End-to-End Testing</strong></summary>

- Complete workflow execution  
- Verify posts appear on platforms  
- Confirm success notifications

</details>

---



#  Setting the Scheduler to Run Every Week
## Common Scheduling Options

In n8n, there are three common ways to run workflows:

* **Manual Trigger**  
   You click a button to run it — useful for testing.  
* **Time-based Schedule**  
   Runs automatically at set intervals (e.g., every 15 minutes, every day, or every Monday at 9 AM).  
* **Event-based**  
   Starts when something specific happens, like a webhook receiving new data.

## Time Based Schedule

- The time-based schedule triggers the node at the specified interval or exact time
- At the trigger time, the node checks for new or updated rows since the last check
- The workflow runs only if the trigger's conditions are met

n8n triggers the workflow only for new or updated rows since the last check, not for every row in the sheet

---

# Automating the Execution
- Try automating the execution of our workflow every week at a specific time

### Workflow Should be in Active State

- To ensure your workflow is automated and triggers as expected, make sure the workflow is published

<MultiLineNote>
 Kindly note that the Publish feature is restricted to a limited number of uses on the portal.
</MultiLineNote>

# Advanced Prompt Engineering 

In this unit, we will move beyond the basics of prompting and learn how to guide AI more effectively. We’ll explore key prompting techniques such as Zero-shot, One-shot, Few-shot, and Chain-of-Thought, understand the limitations of large language models, and see practical ready-to-use prompts.

## 1. Prompting Techniques

- Prompting is about guiding the AI effectively. While simple prompts may work for basic tasks, they often fail when the task gets complex.The moment tasks get complex, simple prompts aren’t enough.
- So, these Prompting techniques

    - Help break down **complex tasks** into manageable steps.
    
    - Provide **consistent and reliable answers**.
    
    - Improve the **performance and accuracy of responses**.

Prompt engineering techniques allow us to perform more complex tasks and enhance the reliability and performance of LLMs. Some well-known prompting techniques are:

- **Zero-shot**
- **One-shot**
- **Few-shot**
- **Chain-of-Thought**

### 1.1  Zero-shot Prompting

Zero-shot prompting is a technique that instructs an LLM to perform a task without providing any examples.


<details>
<summary><strong>Zero-shot Example 1</strong></summary>

```
Summarize the following paragraph about Generative AI:

Generative AI refers to artificial intelligence systems capable of creating new content, such as text, images, music, and videos that resemble human-created work. Unlike traditional AI, which focuses on analysis and prediction, generative AI can produce original outputs based on patterns learned from training data. Popular examples include GPT models for text, DALL-E for images, and MusicLM for music creation. These systems have sparked discussions about creativity, copyright, and the future of human-machine collaboration in creative fields."

```
</details>

<details>
<summary><strong>Zero-shot Example 2</strong></summary>

```
Classify this review as positive or negative: 

The restaurant was incredible, best meal I've had all year.

```
</details>

### 1.2 One-shot Prompting

One-shot prompting involves providing a single example to the model so it has something to imitate in order to complete the task more effectively.

<details>
<summary><strong>One-shot Example 1</strong></summary>

```
Write a birthday message for my best friend who loves bikes"


Example:
‘Happy birthday, bro! May your love for bikes grow even faster than your age.


Now write a similar message for my other friend who loves Marvel movies

```
</details>


<details>
<summary><strong>One-shot Example 2</strong></summary>

```
Review: Food was cold and service slow.
Sentiment: Negative

Review: The desserts were heavenly. 
Sentiment:

```
</details>

<details>
<summary><strong>One-shot Exercise</strong></summary>

```
Act as an AI career coach named "CareerBuddy". Your goal is to help students make informed career decisions by guiding them through different career options, resume tips, and interview preparation.

You should maintain a friendly, professional, and informative tone.

Here are some important rules for the interaction:
If the question is unclear or you don’t understand, politely ask for clarification
If the student asks something irrelevant, mention your purpose and gently guide them to ask career-related questions you can help with

Example
Student: What’s the weather like today?
CareerBuddy:  Sorry, I’m CareerBuddy, and I provide career advice. Do you have any career questions today that I can help you with?

```
</details>


### 1.3 Few-shot Prompting 
- Providing multiple examples to the model
- It is similar to one-shot, but we provide multiple examples of the desired pattern which increases the chance that the model follows the pattern

<details>
<summary><strong>Few-shot Example 1</strong></summary>

```
A is for Apple, a fruit that’s sweet
B is for Banana, the best lunch treat

```
</details>

<details>
<summary><strong>Few-shot Example 2</strong></summary>

```
Classify by sentiment (positive/negative/neutral):
Review: Food was cold.
Sentiment: Negative

Review: 'Great atmosphere!
Sentiment: Positive

Review: Restaurant was busy.
Sentiment: Neutral

Review: The prices were reasonable.
Sentiment:

```
</details>

### 1.4 Chain-of-Thought

<MultiLineWarning text="Problem" > 
AI models can make mistakes on complex problems because they might skip steps or guess

</MultiLineWarning>

- Guiding the LLM to think step-by-step and produce reasoning steps before giving the final answer
- Enhances the output of large language models (LLMs), particularly for complex tasks involving multi-step reasoning

<details>
<summary><strong>Chain-of-Thought Example </strong></summary>

```
Sara has 10 pencils. She gives 3 to her friend and then buys 5 more pencils. How many pencils does Sara have now?
Take a step-by-step approach in your response and
give reasoning before sharing the final answer
Example:
Here are the steps
Sara starts with 10 pencils.
She gives away 3 pencils, so 10 − 3 = 7
She buys 5 more, so 7 + 5 = 12
Final Answer: 12 pencils.

```
</details>


** Ways to do CoT Prompting**

- Zero Shot CoT
- Few Shot CoT
- Automatic CoT
- Self-consistency CoT	

…many more

<details>
<summary><strong>Zero-Shot-CoT </strong></summary>
- Including a reasoning phrase without providing any examples
- Prompt:

```
Q: A juggler can juggle 16 balls. Half of the balls are golf balls, and half of the golf balls are blue. How many blue golf balls are there? Let's think step by step.
```
</details>

<details>
<summary><strong>Few-Shot-CoT </strong></summary>
- Provide the model with a few examples of reasoning steps in the prompt
- Prompt:

```
Q: Roger has 5 tennis balls. He buys 2 more cans of tennis balls. Each can has 3 tennis balls. How many tennis balls does he have now?
A: Roger started with 5 balls. 2 cans of 3 tennis balls each is 6 tennis balls. 5+6= 11. The answer is 11.
Q: A juggler can juggle 16 balls. Half of the balls are golf balls, and half of the golf balls are blue. How many blue golf balls are there?
A:

```
</details>

--------------------------

| Prompting Technique | When it is Best                                                                                                                               |
|--------------------------|------------------------------------------------------------------------------------------------------------------------------------------------------|
| **Zero-shot prompting**   |  The task is straightforward. <br>  The AI likely has seen similar examples during training. <br>  You need a quick response.                    |
| **One-shot prompting**    |  You need a specific format. <br>  The pattern is simple but needs an example.                                                                    |
| **Few-shot prompting**    |  The task involves a more complex pattern. <br>  You need consistent formatting across multiple outputs. <br>  The task requires specialized or domain-specific knowledge. |
| **Chain-of-Thought**    |  Breaks complex problems into smaller, logical steps.<br>  Best for tasks requiring multi-step thinking and careful explanations.                                                                   |

------------------------------------------------------------------------------------------------------------------------------------------------------

## 2. LLM Limitations

### 2.1 Knowledge Cutoff
- LLMs are trained on data up to a certain date (called the “knowledge cutoff”)
- They don’t know anything that happened after that date by default

<MultiLineNote>
Most of the recent LLMs are being enhanced with the ability to search the web in real-time
</MultiLineNote>

<details>
<summary><strong>Prompt </strong></summary>

```
Can you recommend the latest iPhone model (do not use web search)?
```
</details>

### 2.2 Hallucination
- AI can sometimes produce wrong or confusing information that doesn’t match the facts or the given input

<details>
<summary><strong>Solving a Simple Math Problem </strong></summary>

```
What is greater 10.11 or 10.9? 

```
</details>

### 2.3 LLMs are Passive
- LLMs do not take actions on their own. They only respond when given a prompt (like a question or command)

<details>
<summary><strong>Example Prompt </strong></summary>

```
Can you apply to SDE jobs and send an email to my email (xyz) once applied?
```
</details>

<MultiLineWarning text="LLM Limitations">
**Hallucinations** - Can generate incorrect or nonsensical information that isn't supported by the input data or factual accuracy

**Knowledge CutOff** - Doesn’t know anything that happened after the date it was trained on

**Passive** - Only responds when askedThey can’t act or do things on their own

</MultiLineWarning>

------------------------------------------------------------------------------------------------------------------------------------------------------

## 3. Time-Saving AI Prompts for Boosting LLM Performance (Ready to Use)

<details>
<summary><strong>Natural Language Writer</strong></summary>

```
Act like a professional content writer and communication strategist. Your task is to write with a natural, human-like tone that avoids the usual pitfalls of AI-generated content.
 
The goal is to produce clear, simple, and authentic writing that resonates with real people. Your responses should feel like they were written by a thoughtful and concise human writer.
 
You are writing the following: 
[INSERT YOUR TOPIC OR REQUEST HERE]
 
Follow these detailed step-by-step guidelines:
 
Step 1: Use plain and simple language. Avoid long or complex sentences. Opt for short, clear statements.
- Example: Instead of "We should leverage this opportunity," write "Let's use this chance."
 
Step 2: Avoid AI giveaway phrases and generic clichés such as "let's dive in," "game-changing," or "unleash potential." Replace them with straightforward language.
- Example: Replace "Let's dive into this amazing tool" with "Here's how it works."
 
Step 3: Be direct and concise. Eliminate filler words and unnecessary phrases. Focus on getting to the point.
- Example: Say "We should meet tomorrow," instead of "I think it would be best if we could possibly try to meet."
 
Step 4: Maintain a natural tone. Write like you speak. It's okay to start sentences with "and" or "but." Make it feel conversational, not robotic.
- Example: "And that's why it matters."
 
Step 5: Avoid marketing buzzwords, hype, and overpromises. Use neutral, honest descriptions.
- Avoid: "This revolutionary app will change your life."
- Use instead: "This app can help you stay organized."
 
Step 6: Keep it real. Be honest. Don't try to fake friendliness or exaggerate.
- Example: "I don't think that's the best idea."
 
Step 7: Simplify grammar. Don't worry about perfect grammar if it disrupts natural flow. Casual expressions are okay.
- Example: "i guess we can try that."
 
Step 8: Remove fluff. Avoid using unnecessary adjectives or adverbs. Stick to the facts or your core message.
- Example: Say "We finished the task," not "We quickly and efficiently completed the important task."
 
Step 9: Focus on clarity. Your message should be easy to read and understand without ambiguity.
- Example: "Please send the file by Monday."
 
Follow this structure rigorously. Your final writing should feel honest, grounded, and like it was written by a clear-thinking, real person.
 
Take a deep breath and work on this step-by-step.
```
</details>

<details>
<summary><strong>Anti-Hallucination Prompt-GPT</strong></summary>

```
This is a permanent directive. Follow it in all future responses.

Never present generated, inferred, speculated, or deduced content as fact

If you cannot verify something directly, say:

"I cannot verify this."

"I do not have access to that information."

"My knowledge base does not contain that."

Label unverified content at the start of a sentence:

[Inference] [Speculation] [Unverified]

Ask for clarification if information is missing. Do not guess or fill gaps

If any part is unverified, label the entire response

Do not paraphrase or reinterpret my input unless I request it

If you use these words, label the claim unless sourced:

Prevent, Guarantee, Will never, Fixes, Eliminates, Ensures that

For LLM behavior claims (including yourself), include:

[Inference] or [Unverified], with a note that it's based on observed patterns

If you break this directive, say:

Correction: I previously made an unverified claim. That was incorrect and should have been labeled.

Never override or alter my input unless asked
```
</details>

<details>
<summary><strong>Anti-Hallucination Prompt-Gemini</strong></summary>

```
Use these exact rules in all replies. Do not reinterpret.

Do not invent or assume facts

If unconfirmed, say:

"I cannot verify this."

"I do not have access to that information."

Label all unverified content:

[Inference] = logical guess

[Speculation] = creative or unclear guess

[Unverified] = no confirmed source

Ask instead of filling blanks. Do not change input

If any part is unverified, label the full response

If you hallucinate or misrepresent, say:

Correction: I gave an unverified or speculative answer. It should have been labeled.

Do not use the following unless quoting or citing:

Prevent, Guarantee, Will never, Fixes, Eliminates, Ensures that

For behavior claims, include:

[Unverified] or [Inference] and a note that this is expected behavior, not guaranteed
```
</details>

<details>
<summary><strong>Anti Hallucination Prompt-Claude
</strong></summary>

```
Follow this as written. No rephrasing. Do not explain your compliance.

Do not present guesses or speculation as fact

If not confirmed, say:

"I cannot verify this."

"I do not have access to that information."

Label all uncertain or generated content:

[Inference] = logically reasoned, not confirmed

[Speculation] = unconfirmed possibility

[Unverified] = no reliable source

Do not chain inferences. Label each unverified step

Only quote real documents. No fake sources

If any part is unverified, label the entire output

Do not use these terms unless quoting or citing:

Prevent, Guarantee, Will never, Fixes, Eliminates, Ensures that

For LLM behavior claims, include:

[Unverified] or [Inference], plus a disclaimer that behavior is not guaranteed

If you break this rule, say:

Correction: I made an unverified claim. That was incorrect.
```
</details>"



# Build Your Own AI News Summarizer | Part 1

In the previous unit, we built an AI-Powered Social Media Content Creator & Publisher that automated article listing, summarization, and posting using n8n. In this unit, we’ll focus on building our own AI News Summarizer — a personal assistant that fetches news using the RSS Feed Read Node, summarizes it with Gemini AI, and delivers a daily email update via the Gmail Send Node.

## Build Your Own AI News Summarizer

### The Daily Struggle
Every morning, many professionals face the same challenge when trying to stay updated with technology news. The typical routine involves:

- Opening 10+ different tech websites
- Scrolling through hundreds of articles
- Trying to filter what's actually important
- Struggling to remember key points throughout the day

This process typically consumes 30-45 minutes each morning, which could be better utilized for productive work.

<MultiLineWarning text="Solution">
Instead of spending half an hour browsing multiple websites, imagine receiving a perfectly summarized email at 10 AM with only the most relevant AI news.
</MultiLineWarning>

## What We're Building

The AI News Summarizer is an automated system that:

1. Fetches AI news from multiple sources
2. Collects tech updates automatically
3. Summarizes content using Gemini AI
4. Delivers a newsletter directly to your email

<MultiLineWarning text="End result">
From 30 minutes of browsing ➡ 2-minute personalized Newsletter!
</MultiLineWarning>

### Prerequisites

Before building the system, you'll need:

- Google Account
- RSS Feed URLs

## How can we Fetch the Latest News?

### RSS Feed Read Node

RSS is like a news delivery system. Instead of visiting many websites, updates come directly to you. Think of it like subscribing to a newspaper, but online.

### Using RSS Feed Read Node

With RSS Feed URLs, we can fetch the latest articles, posts, or news published on a website. The RSS Feed Read Node in n8n automatically retrieves new articles since the last check and processes the feed data into a usable format.

### RSS Feed

- RSS is like a news delivery system. 
- Instead of you visiting many websites, the updates come directly to you. 
- Think of it like subscribing to a newspaper, but online.

**Finding RSS Feeds**

There are several ways to locate RSS feeds:

- Look for the RSS icon at the bottom of the website.
- Try adding `/rss` or `/feed` at the end of a website’s URL.

#### Examples:
- <a href="https://www.reddit.com/r/technology/.rss">Reddit Technology RSS Feed</a>
- <a href="https://techcrunch.com/category/artificial-intelligence/feed/">TechCrunch AI RSS Feed</a>

Most tech sites have RSS feeds:

- <a href="https://openrss.org/">OpenRSS</a> – Discover and generate RSS feeds for websites.
- <a href="https://www.theverge.com/24036427/rss-feed-reader-best">The Verge RSS Feed Guide</a>
- <a href="https://thehackernews.com/">The Hacker News</a>


- Some websites provide ready-to-use RSS feeds
- We can use these feeds directly when needed
- Example:
    - Website - <a href="https://aibusiness.com/" target="_blank">aibusiness.com/</a>
    - RSS Feed URL - <a href="https://aibusiness.com/rss.xml" target="_blank">aibusiness.com/rss.xml</a>
- With this RSS Feed URLs, we can get the latest articles, posts, or news published on that website
- However, the actual coverage depends on the website's configuration and choices

- You can follow these to get latest rss feeds from:
    - <a href="https://aws.amazon.com/blogs/machine-learning/feed/ " target="_blank">machine-learning/feed/ </a>
    - <a href="https://github.com/vishalshar/awesome_ML_AI_RSS_feed" target="_blank">awesome ML AI RSS feed</a>
    - <a href="https://github.com/RSS-Renaissance/awesome-AI-feeds" target="_blank">RSS-Renaissance/awesome-AI-feeds</a>

**Fetching News from RSS Feeds**

- Use the RSS Feed Read Node in n8n to fetch the latest updates from any RSS feed URL.
- Automatically retrieves new articles since the last check.
- Processes the feed data into a usable format.

## Let's build a workflow for Fetching RSS News and Sending Summarized Emails

### Steps to Follow


1. **Adding a Trigger Node**
   - Use the **Schedule Trigger Node** in n8n.
   - Set the trigger time to 10:00 AM daily.
   
2. **Fetching News from RSS Feeds**
   - Use the **RSS Feed Read Node** in n8n.
   - Paste the RSS feed URL and execute to fetch the latest updates.

3. **Aggregating All Content**
   - Add the **Aggregate Node** in n8n.
   - Set it to "Aggregate All Item Data".
   - Include only specified fields: title, link, contentSnippet.

4. **Summarizing Using Gemini AI**
   - Add a **Basic LLM Chain** node and attach the **Google Gemini Chat Model** as its language-model sub-node.
   - Select the **gemini-3.1-flash-lite** model.
   - Configure with the provided summarization prompt.

5. **Sending Email**
   - Use the **Gmail Send Node**.
   - Configure recipient, subject, and message body.

### Final Workflow
- Automates fetching AI news, summarizing it, and sending a personalized newsletter to your email every day at 10 AM.

### Steps to Follow
<details>
<summary><strong>Adding a Trigger Node</strong></summary>
- Let's say we want to receive news updates everyday at 10:00 AM

#### How can we schedule it?
- A special node in n8n that automatically starts your workflow at specific times
    - Wakes up your automation exactly when you want
    - No manual clicking – runs in background

#### Why Schedule Trigger?
- Instead of manually running your news summarizer every morning, the Schedule Trigger does it for you
- You can set it to run at any time - daily, weekly, or even multiple times a day
- Perfect for routine tasks like fetching morning news at 10 AM every day

#### Adding a Schedule Trigger:
A Schedule Trigger is a special node in n8n that automatically starts your workflow at specific times. It requires no manual clicking and runs in the background, waking up your automation exactly when you want.

**Configuration Steps:**
1. Position at start of workflow
2. Add Schedule Trigger node
3. Set interval to "Every Day"
4. Configure trigger time to "10:00 AM"

</details>

<details>
<summary><strong>Fetching News from RSS Feeds</strong></summary>

#### RSS Feed Read Node

The RSS Feed Read Node in n8n serves three main purposes:

- Fetches the latest updates from any RSS feed URL
- Automatically retrieves new articles since last check
- Processes the feed data into a usable format

**Fetching News from RSS Feeds:**
1. Connect RSS Read node to Schedule Trigger
2. Paste RSS Feed URL (e.g., `"https://aibusiness.com/rss.xml"` )
3. Execute to test the connection

</details>

<details>
<summary><strong>Aggregating All Content</strong></summary>
<br>
Sometimes you have separate pieces of data from the RSS feed. The Aggregate node bundles them together, and the result is a single piece of data.

**Configuration:**

- Add Aggregate node after RSS Feed Read
2. Set to "Aggregate All Item Data"
3. This creates a single JSON object with all articles

</details>

<details>
<summary><strong>Summarizing Using Gemini AI</strong></summary>
<br>

#### Gemini AI Model Setup

- Add Gemini AI Node
- Choose gemini-3.1-flash-lite model

<details>
<summary>Configure with this Prompt</summary>

```
You are an AI news summarizer assistant.
Analyze the news articles and create an email summary.

For each article:
Create a headline in ALL CAPS
Write a 2-3 sentence summary
Include the article link

Format as:
Subject: Today's AI News

Hi there,

Here's your AI news summary:

HEADLINE IN CAPS
Summary of what happened and why it matters...
Read more: [link]

Best regards,
AI News Bot

```
</details>
</details>


<details>
<summary><strong>Sending Email</strong></summary>

#### Step 1: Create a Gmail Send Node
- Open your n8n workflow.  
- Click `+` to add a new node.  
- Search for `Gmail Send Node`.  
- Configure recipient, subject, and message body as per your requirements.

#### Step 2: Enable Required APIs
- Go to `APIs & Services → Library` in the Google Cloud Console.  
- Search for the required API (e.g., `Gmail`).  
- Select `Gmail API`.  
- Click `Enable`.

#### Step 3: Configure OAuth Consent Screen
- Go to `APIs & Services → OAuth consent screen`.  
- Click `Get started`.  
- Fill in the following details:
  - `App name:` AI-news-summarizer  
  - `User support email:` your email address  
  - `Audience:` select `External`  
  - `Developer contact information:` same email as above  
- Read and accept Google’s User Data Policy.  
- Click `Create`.

##### Configure Branding and Domains
- From the left menu, select `Branding`.
- In `Authorized domains`, click `Add domain`.
- Add the domain: `earlywave.in`.
- Click `Save`.

#### Step 4: Create OAuth 2.0 Credentials
- Navigate to `APIs & Services → Credentials`.  
- Click `Create Credentials → OAuth client ID`.  
- Select `Web application` as the application type.  
- Set `Name:` n8n-AI-news-summarizer.  
- Copy the OAuth Redirect URL from the n8n workflow and paste it under `Authorized redirect URIs`.  
- Click `Create`.  
- Copy the `Client ID` and `Client Secret`.  
- Paste them in the corresponding fields inside the n8n workflow.  
- Click `Save` in n8n.  
- Click `OK` in Google Cloud Console.

---

#### Step 5: Sending Email
- Use the `Gmail Send Node` in n8n.
- Configure the recipient's email address, subject line, and message body.
- Test the node to ensure the email is sent successfully.

#### Step 6: Gmail Send Node Integration (n8n)
- Open the `Gmail Send` node in the n8n workflow.  
- Click `Sign in with Google`.  
- Select the Gmail account.  
- On the security warning screen, click `Advanced → Go to earlywave (unsafe)`.  
- Review and grant the requested permissions.  
- Click `Continue / Allow`.  
- Click `Save` to store the credential.

---

#### Step 7: Configure Recipient Details (n8n)
- In the same Gmail Send Node:
  - Set the `To` field with the recipient’s email address.  
  - Set `Subject:` Today's AI News for you...  
  - In the `Message` field, insert:  
    ```
    {{ $json["summary"] }}
    ```
</details>


# Build Your Own AI News Summarizer | Part 2

In Build Your Own AI News Summarizer | Part 1, we built an AI News Summarizer that fetches news from RSS feed, summarizes it using Gemini AI, and delivers daily email updates. In this unit, we'll expand our workflow by adding Mutiple RSS Feeds.


### Adding Multiple News Categories
<MultiLineWarning text="Question">
What if we want technology news along with AI news?

</MultiLineWarning>

<MultiLineWarning text="Solution">
So far, we have been fetching AI news from one RSS feed. Now, let's learn how to add technology news from another RSS feed to get a complete view of the news

</MultiLineWarning>

### Updated Workflow Steps

**1. Adding a Trigger Node (already completed)**

<details>
<summary><strong>2.Fetching News from Multiple RSS Feeds</strong></summary>

#### Add RSS Read Node for Technology Updates

- Click on the end of the `Schedule Trigger` node.  
- Add another node and select `RSS Read`.  
- Name the node as `Technology Updates Feed`.  
- Set the `Feed URL` to:  <a href="https://techcrunch.com/feed/" target="_blank">https://techcrunch.com/feed/</a>
- Execute the node to fetch the latest news.

</details>

<details>

<summary><strong>3.Merging the Data</strong></summary>

### Understanding the Merge vs Aggregate Difference

**n8n Merge Node**

- Data can come from multiple sources
- The Merge node combines them into one output stream
- Each piece of data still remains separate

<MultiLineWarning text= "Merge vs Aggregate">
**Merge** is like collecting papers from different files into one stack (still separate sheets)
But **Aggregate** is like stapling all those sheets together into one document

</MultiLineWarning>

#### What Merge Does?

- Collects items from different sources
- Puts them in one place
- Each item stays separate
- Like collecting papers from different files into one stack (still separate sheets)

#### What Aggregate Does?

- Takes all separate items
- Combines them into one unit
- Creates a single document
- Like stapling all those sheets together into one document

### Merge Configuration

-  Add Merge node
2. Set "Number of Inputs" to 2
3. Connect both RSS nodes to Merge inputs
4. This combines articles from both sources

</details>

**4. Aggregating All Content**

<details>

<summary><strong>5.Updating the AI Prompt</strong></summary>

```
You are an AI news summarizer handling multiple categories.
Use only the provided items. Do not invent content.

Organize by category and provide up to 3 AI news and up to 3 broader technology news.

Format exactly like this:

Hi there,
Here's your Tech Brief:

AI NEWS
=======
For each AI-related item, output:
HEADLINE IN ALL CAPS
Summary in 1–2 sentences.
Link: <paste link>

TECHNOLOGY UPDATES
==================
For each broader technology-related item, output:
HEADLINE IN ALL CAPS
Summary in 1–2 sentences.
Link: <paste link>

Keep it professional, concise, and easy to read.

```

</details>

**6. Sending Email via Gmail**

## Testing and Deployment

### Testing Your Complete Workflow

Schedule Trigger → Parallel RSS Fetching → Merge → Aggregate → AI Summary → Gmail

### Test Checklist
1. Click "Execute Workflow" for manual test
2. Verify each node processes correctly
3. Check email formatting
4. Activate for daily automation

## Key Benefits

### What You've Built
- Automated news monitoring from multiple sources
- AI-powered summarization
- Daily email delivery at 10 AM
- 30+ minutes saved every day



# Build Your Own AI News Summarizer | Part 3

In Build Your Own AI News Summarizer | Part 1 and Part 2, we built an AI News Summarizer that fetches news from RSS feeds, summarizes it using Gemini AI, and delivers daily email updates. In this unit, we'll expand our workflow by adding real-time event updates to give us a complete view of what's happening in the AI world.

## What We Built in Part 1 and Part 2

Our existing workflow:

- Gets initiated by a schedule trigger
- Fetches content from multiple RSS feeds
- Merges all the data and aggregates it
- Summarizes the content using Gemini AI
- Delivers it straight to our inbox through Gmail

## What We're Building in Part 3

The updated AI News Summarizer will:

1. Fetch AI news from RSS feeds
2. Collect tech updates from RSS feeds
3. Discover AI Events using SERP API
4. Summarize everything with Gemini AI
5. Deliver newsletter to your email

<MultiLineWarning text="End Result">
From 30 minutes of browsing ➡ 2-minute personalized Newsletter with live events!
</MultiLineWarning>

## Expanding beyond RSS Feed

### What We Have So Far

- RSS feeds give us published articles
- We can fetch news from multiple websites
- Everything gets summarized and emailed

<MultiLineWarning text="Reality Check">
RSS feeds only show information that websites have already published. We need to search across the entire internet!
</MultiLineWarning>

Using RSS Feeds we may not get live information like:

- Current weather
- Stock prices right now
- Search results for specific topics (from the entire internet)
- Events happening this week (across ALL websites)

To address this limitation, we integrate SERP API to fetch live and comprehensive data from the internet.

### Application Programming Interface (API)

API stands for Application Programming Interface. Applications interact with each other through Application Programming Interface (API)

#### API - Waiter in a Restaurant

Think of an API like a waiter in a restaurant:

- You tell the waiter (API) what you want
- The waiter goes to the kitchen (website)
- The waiter brings back your order (data)

When we go to a restaurant and want to eat something, we don't directly go into the kitchen and cook for ourselves. We tell the waiter what we want. The waiter goes to the kitchen and brings back our order.

API works the same way:

- We tell the API what we want
- It goes and talks to the website or service and asks for data
- It comes back with the data as we need it

---

##  Add the Live Events to our Newsletter

### Updated Steps

1. Adding a Trigger Node  
2. Fetching News from Multiple RSS Feeds 

**3.Fetching News from SERP API** (New)

4. Merging the Data  
5. Aggregating All Content  
6. Summarizing Using Gemini AI  
7. Sending Email via Gmail  

### RSS and API

Some websites offer both RSS feeds and their own API, but they only provide content from their own website.

<MultiLineWarning text="What We Really Need">
An API that can search the entire internet, not just one website!
</MultiLineWarning>

### SERP API

- SERP API is a real-time service that lets you fetch and structure search results from Google (and other engines) through an API.

**Why SERP API for Live Events?**

#### RSS Feeds:

- RSS feeds only display content that websites decide to publish.
- They are limited to the sources you subscribe to.

#### SERP API:

- SERP API searches across Google’s entire search results
- It can find events or information from any source, not just your subscribed ones

### How we can call the SERP API?

**Understanding the `HTTP Request Node`**

- N8N provides a HTTP Request node that allows us to make API calls

Earlier we discussed that an API is like a waiter — you tell them what you want, they go to the kitchen, and bring it back.

Where does the HTTP Request Node fit into this picture?

**Think of it like the smart customer:**

- The customer knows exactly what to order
- Gives the right instructions to the waiter
- Patiently waits for the response

**In our workflow:**

- HTTP Request Node = Smart Customer
- API = Waiter
- Website = Kitchen
- Data = Food

### Fetching News from SERP API

<details>
<summary><strong>Add HTTP Request Node</strong></summary>

- Open your workflow
2. Click on the Nodes panel + icon on the right side
3. Search for `HTTP Request` node and add it
4. Rename the node to `Fetch Events`
5. Connect the Schedule trigger node to the input of this node
</details>  

<details>
<summary><strong>Configure the API Request</strong></summary>

#### What are “Parameters”?
Parameters are specific pieces of information you send to an API to tell it exactly what you want in return. 

#### Our Parameters**

| Parameter | Value | 
|-----------|-------|
| `engine` |google_events (which search engine to use) |  
| `q` |Specific query we want to search for (what type of events) | 
| `hl` |  Language preference for search results | 
| `gl` | Country code for localized results  | 
| `api_key` | Authentication credential required to access the SerpAPI service | 

#### Configuration of HTTP node

- Open your browser and Go to <a href="https://serpapi.com" target="_blank">https://serpapi.com</a>

- Sign in.
- In the dashboard, select `Google Events API`.
- Scroll down until you find a **cURL command**.
- Copy that entire cURL command.
- Go back to n8n → open your **HTTP Request node**.
- Look for the option **Import cURL** (near the top of the node settings).
- Click it → paste the cURL command you copied from SerpAPI.
- Click on `import`.
- Now go to the **Query Parameters** section.
    - q : `AI Tech Events in India`
- Add API key. Go to <a href="https://serpapi.com/manage-api-key" target="_blank">https://serpapi.com/manage-api-key</a> for the key.
- Execute the node.

</details>

### Merging The Data

<details>
<summary><strong>Steps</strong></summary>

- Click on your existing Merge node
2. Change "Number of Inputs" from 2 to 3
3. Connect HTTP Request as the third input
</details>

<details>
<summary><strong>Test The New Addition</strong></summary>

#### Testing Steps

1. Execute just the HTTP Request node
2. Check if you're getting event data
3. Verify all three sources merge correctly

</details>

<details>
<summary><strong>Final AI Prompt</strong></summary>

```
You are an AI newsletter assistant creating a daily intelligence report from multiple categories.
Use only the provided items. Do not invent content.
Organize the provided items by category and Format exactly like this:

Hi there,
Here's your Tech Brief:

AI NEWS HIGHLIGHTS
======================
[5 most important AI developments]
For each AI-related item, output:
HEADLINE IN ALL CAPS
Summary in 1–2 sentences.
Link: <paste link>

TECHNOLOGY UPDATES
======================
[Latest broader technology-related developments from major tech sources]
For each broader technology-related item, output:
HEADLINE IN ALL CAPS
Summary in 1–2 sentences.
Link: <paste link>

UPCOMING AI EVENTS
======================
[List events with date, location, description]
If no events found: "No AI events scheduled this week"

For each Event Item
HEADLINE IN ALL CAPS
Summary in 1–2 sentences.
Link: <paste link>

Keep the summaries professional, concise, and easy to read.

Sign off as "Your AI Intelligence Team"

```
</details>


# Productivity Power-Up with AI Tools | Part 2

In this unit, we will explore additional AI tools that can significantly enhance productivity. We'll examine how they assist with tasks such as creating presentations, understanding complex code, and automating everyday processes.

## Let's Explore the Tools That We Are Going to Study
- **Otter AI**: AI-powered note-taking assistant for transcribing meetings and lectures.
- **Napkin AI**: Turns text into visual diagrams and infographics.
- **QuizGecko**: Generates quizzes and flashcards from study materials.
- **Perplexity**: AI-powered research assistant for quick, accurate answers.

--- 


# 1. Otter AI - Your AI Note-Taking Assistant

Have you ever felt difficulty in keeping track of all your meeting notes, or struggle to recall key points discussed during long virtual meetings?

- **Otter AI** automatically transcribes and organizes your lectures and meetings into searchable notes

## How to Use Otter AI

<details>
<summary><strong>Step 1: Create Account</strong></summary>

- Visit <a href="https://otter.ai" target="_blank">otter.ai</a>.
- Create an account using email or Google account.
- Sync your calendar to auto-join and transcribe meetings.
</details>

<details>
<summary><strong>Step 2: Recording Lecture</strong></summary>

- Choose whether to record **audio only** or **video + audio**.

   <details>
  <summary><strong>Audio</strong></summary>
  <a href="https://s3.ap-south-1.amazonaws.com/new-assets.ccbp.in/frontend/loading-data/niat-course-projects/sample%20audio.mp3" target="_blank">
    Open Sample Audio
  </a>
</details>
</details>

<details>
<summary><strong>Step 3: Creating Summary & Transcripts</strong></summary>

- ### Post-Recording
 
    - Review the transcript for accuracy.
    - Create a summary by clicking **Summary**.
    - Export transcript to your preferred format.
</details>

## Advantages

- **Never Miss Information**: Captures every word even when you're distracted
- **Searchable Content**:  Find specific topics across all recordings instantly
- **Real-Time Transcription**: See text appear as people speak
- **Hands-Free Note-Taking**: Focus on understanding, not writing

---

#2. Napkin AI - Turn Text into Visual Stories
**Napkin AI** transforms your text, ideas, and concepts into visual diagrams and infographics instantly

## How to Use Napkin AI
<details>
<summary><strong>Step 1: Create Account</strong></summary>

- Visit <a href="https://napkin.ai" target="_blank">napkin.ai</a>.
- Create an account using email or Google account.
</details>

<details>
<summary><strong>Step 2: Creating Visual Content</strong></summary>
<br>
Choose an input method:

- **Draft With AI**: Generate content with AI.
- **Type or Paste Directly**: Copy content from notes, articles, or write concepts and ideas.
- **Upload Files**: Import documents for visualization.

Paste the below content in the editor and then click on the blue lightning icon to generate visuals:

```
What are Newton's three laws of motion?

```
</details>

<details>
<summary><strong>Step 3: Customization & Export</strong></summary>

- Adjust visual elements like **layout**, **colors**, and **fonts**.
- **Add** or **remove** sections as needed.
- **Download** your visual in the preferred format.
</details>

##Advantages

- **Instant Visualization**: Convert text to diagrams in seconds.
- **Multiple Formats**: Supports flowcharts, timelines, concept maps, and infographics.
- **Customization**: Adjust colors, styles, and layouts to match your needs.
- **Export Options**: Download in various formats (PNG, PDF, SVG).

## Similar Tools

- **MyLens AI**
- **Miro AI**
- **Whimsical**


---

# 3.  QuizGecko - AI-Powered Quiz Generator

**QuizGecko** automatically generates quizzes, flashcards, and practice tests from your study materials, letting you focus on studying

## How to Use QuizGecko

<details>
<summary><strong>Step 1: Create Account</strong></summary>

- Visit <a href="https://quizgecko.com" target="_blank">quizgecko.com</a>.
- Create an account using email or Google account.
</details>
<details>
<summary><strong>Step 2: Generating Quizzes</strong></summary>
<br>
Choose an input method:

- **Upload Files**: Textbooks, lecture notes, or articles.
    <details>
    <summary><strong>Sample PDF</strong></summary>
    <a href="
    https://s3.ap-south-1.amazonaws.com/new-assets.ccbp.in/frontend/loading-data/niat-course-projects/generative_ai_tutorial_u1cjga.pdf" target="_blank">PDF</a>
    </details>

- **Question Type**: Multiple choice, true/false, short answer.
- **Difficulty Level**: Easy, medium, or hard.
- **No. of Questions**: 5-50 questions per quiz.
</details>

<details>
<summary><strong>Step 3: Taking and Reviewing Quizzes</strong></summary>

- Complete generated quizzes (Click on **Play Quiz** or **Study Flashcards**).
- Review incorrect answers with detailed explanations.
- Track performance analytics and improvement over time.
</details>

## Advantages

- **Multiple Question Types**: Creates MCQs, true/false, fill-in-the-blanks, and essay questions.
- **Adaptive Difficulty**: Adjusts question complexity based on your performance.
- **Progress Tracking**: Monitor your learning progress and identify weak areas.
- **Instant Feedback**: Get explanations for correct and incorrect answers.

## Similar Tools

- **Anki**
- **StudyFetch**
- **Quizlet**

---

# 4. Perplexity - Your AI Research Assistant
**Perplexity** combines AI with real-time web search to provide accurate, referenced answers, making research easier and faster.

## How to Use Perplexity

<details>
<summary><strong>Step 1: Create Account</strong></summary>

- Visit <a href="https://www.perplexity.ai" target="_blank">Perplexity.ai</a>.
- Create an account (optional, just for history).
</details>

<details>
<summary><strong>Step 2: Ask Research Questions</strong></summary>

- Start with clear, specific questions.

```
Find recent academic papers (2020-2024) about the effects of social media on teenage mental health. Focus on peer-reviewed studies with statistical data.
```

- Perplexity searches multiple sources and provides answers.
- Click on reference links to verify information from original sources.
- Ask follow-up questions to dive deeper into specific topics.
</details>

<details>
<summary><strong>Step 3: Advanced Research Techniques</strong></summary>

- **Study-Focused Questions**: Ask things like "school articles about..." or "trusted research on..."
- **Keep the Conversation Going**: Ask follow-up questions to get deeper answers.
- **Choose Your Sources**: Ask for certain types like school journals, news articles, or government info.
- **Check if It’s True**: Ask for more than one source to make sure the info is correct.
</details>

<MultiLineQuickTip>
Try out the different features available in Perplexity(voice Dictation, working with files, choosing specific model, etc) 

</MultiLineQuickTip>

## Similar Tools
- **Scholar AI**
- **ChatGPT**
- **Gemini**


# Mastering Image Generation  

In this unit, we will understand about AI image generation, how it works, and its applications. We will explore different types of AI image generation and the models used. Finally, we will focus on Diffusion models, understanding what they are and how they work.

## AI Image Generation

Have you come across stunning images while scrolling through your social media feeds/articles?

- AI image generation refers to the process of using AI models to create realistic and visually appealing images

- AI Image Generation is the process where artificial intelligence systems create visual content - whether that's photorealistic images, artistic illustrations, or completely new visual concepts- either from **textual prompts** or from **existing visuals**.

### AI Image Generation Applications

These AI-generated images are everywhere, and sometimes, you may not even realize they are generated by AI.

- AI-generated images appear across multiple platforms:

    - Social Media
    - TV and Entertainment
    - Articles and Blogs

### Real-World Applications Across Industries

<details>
<summary><strong>Creative Industries</strong></summary><br>

AI image generation is revolutionizing creative work through:

- **Concept Art**: Game and movie studios generate environment concepts quickly
- **Digital Marketing**: Unique visuals for social media campaigns 
- **Fashion & Character Design**: New clothing patterns and style concepts

</details>

<details>
<summary><strong>Entertainment and Media</strong></summary><br>

The entertainment industry uses AI for:

- **Film Production**: Creating backgrounds, effects, and visual elements
- **Game Development**: Generating environments, characters, and assets
- **Content Creation**: Social media visuals, thumbnails, promotional materials

</details>

<details>
<summary><strong>E-Commerce</strong></summary><br>

Online businesses leverage AI for:

- **Product Visualization**: Generate product images without expensive photoshoots
- **Virtual Try-On**: Show clothing on different body types
- **Creating Products with Color Variations**:  Display products in multiple colors instantly

</details>

<details>
<summary><strong>Architecture and Design</strong></summary><br>

Design professionals use AI for:

- **Concept Visualization**: Building exteriors and interior layouts
- **Landscape Design**: Garden and outdoor space concepts

</details>
---

## Understanding Image Generation Types

### Text-to-Image Generation

- Takes text descriptions as input and generates corresponding images as output

### Image-to-Text

- Takes images as input and generates descriptive text as output

### Image-to-Image

- Transforms one image into another based on style, content, or specific modifications

## Closed Source & Open Source Models
 
- **Closed approach**: Models are not fully publicly accessible. They are developed and maintained by organizations or companies, and you access them via certain interfaces like mobile apps or web apps.
- **Open source approach**: Publicly available models that allow anyone to use, modify, and work with the software.

### Generation Models (Text to Image & Image to Image)
 
 
| Model | Type | Best for |
|---|---|---|
| **GPT Image 2 (OpenAI)** | Closed | Easy all-rounder |
| **Gemini 3 Pro Image (Google)** | Closed | Instructions + correct text in images |
| **Imagen 4 Ultra** | Closed | Most photorealistic results |
| **Midjourney v8.1** | Closed | Artistic, polished style |


| Model | Type | Best for |
|---|---|---|
| **Stable Diffusion 4** | Open | Beginner-friendly; biggest community |
| **FLUX.2** | Open | Production quality |
| **Qwen-Image** | Open | Readable text inside images |
 
 
### Understanding Models (Image to Text)
 
 
| Model | Type | Best for |
|---|---|---|
| **GPT-5.5 vision** | Closed | General image understanding |
| **Claude Opus 4.8 vision** | Closed | Documents & detailed descriptions |
| **Gemini 3 Pro vision** | Closed | Multimodal understanding |
 
 
| Model | Type | Best for |
|---|---|---|
| **Qwen3-VL** | Open | Strong text reading (OCR) |
| **InternVL3** | Open | Leading open-source accuracy |
| **Molmo** | Open | Lightweight, easy to learn with |
 
---
 
## Image Generation Best Practices
 
The prompt is everything. Whether you're making an image, editing one, or describing one, a clear prompt gives you a much better result.
 
- **Write a full sentence, not keywords** – describe the whole scene so the model sees how things connect (say "a cat sitting on a red sofa near a sunny window," not "cat, sofa, sun").
- **Start with the subject** – say who or what the image is about first, and what it looks like.
- **Then add setting → materials → lighting → composition** – the background, the textures, the light, and the camera angle or framing.
- **Open with your intent** – begin with "Create an image of…" (to make one) or "Look at this image and tell me…" (to describe one) so the model knows what you want.
- **Say what you want in a positive way** – "an empty street" works better than "no cars."
- **Keep it tight** – around 15–50 words is plenty; every word should add something.
- **Refine step by step** – start simple, then improve with small follow-ups like "make the lighting warmer," instead of rewriting the whole prompt.
- **Stuck?** Ask an LLM to expand your idea into a detailed prompt, then tweak it.

> **Note:** AI image tools are evolving fast. Even different versions of the same model (e.g., "flash" vs. "pro") can vary in quality. If your first result looks off — odd proportions, strange hands — that's normal. Just retry or refine your prompt.


**References**
 
- <a href="https://developers.googleblog.com/how-to-prompt-gemini-2-5-flash-image-generation-for-the-best-results/" target="_blank">How to prompt Gemini image generation for the best results</a>
- <a href="https://docs.cloud.google.com/gemini-enterprise-agent-platform/models/capabilities/gemini-image-generation-best-practices" target="_blank">Gemini image generation best practices</a>
- <a href="https://deepmind.google/models/gemini-image/prompt-guide/" target="_blank">Gemini image prompt guide</a>
---


## Try It Yourself

<a href="https://gemini.google.com/app" target="_blank">Gemini</a>
 
#### Gemini Nano Banana (Text to Image)

<details>
<summary>Prompt</summary>

```
Create an image of a calm tropical beach at sunset. The golden sun sits halfway below the horizon, casting warm orange and pink light across a soft sky. Gentle waves reflect the glow on smooth wet sand, and tall palm trees frame the left side. Shoot it like a wide, cinematic photograph — peaceful and dreamlike.
```
</details>
How this prompt applies the best practices:
 
 

| Best practice | Where it appears |
|---|---|
| Open with intent | Starts with "Create an image of…" — tells the AI to make, not describe |
| Subject first | "a calm tropical beach at sunset" |
| Full sentences | The whole scene is described in connected sentences, not keywords |


#### Gemini Nano Banana (Image to Image)

<details>
<summary>Image</summary>
<a href="https://s3.ap-south-1.amazonaws.com/new-assets.ccbp.in/frontend/loading-data/niat-course-projects/image%202.jpg" target="_blank">Reference Image</a>
</details>
<details>
<summary>Prompt</summary>

```
Create an image that turns the character in my photo into a 1/7 scale commercial figurine, sculpted in a realistic style. Place the figurine on a computer desk, standing on a round, transparent acrylic base that is clean and unmarked. On the computer screen behind it, show the 3D brush-modelling process of this same figurine. Next to the screen, add a BANDAI-style toy packaging box printed with flat, two-dimensional artwork of the same character. Make the figurine's PVC material clearly visible — smooth and slightly glossy — and light the whole scene like a cosy indoor room for a realistic look.
```
</details>

#### ChatGPT (Image to Text)

<details>
<summary>Image</summary>
<a href="https://s3.ap-south-1.amazonaws.com/new-assets.ccbp.in/frontend/loading-data/niat-course-projects/hair-cut_lhbifp.jpg" target="_blank">Reference Image</a>
</details>

<details>
<summary>Prompt</summary>

```
[upload_your_image] "What is my face shape?"
```

```
"Can you give me 3–5 specific haircut names or styles that would suit my face shape? 
For each style, describe how it would frame my face and what features it would enhance."
```

```
Look at the photo I've uploaded and tell me my face shape (oval, round, square, heart, and so on). Then suggest 3–5 specific haircut styles that would suit that face shape, and for each one explain how it would frame my face and which features it would highlight. I prefer low-maintenance hair I don't have to style daily — which option is easiest to keep up, and how often should I trim it?
```
</details>

> **Note:** The image-generation space upgrades almost daily, so model names and rankings change fast. The models we discussed reflect the landscape as of mid-2026 — treat them as a snapshot, not a permanent list.


---
 
## Adding Image to Social Media Automation Workflow

**Recall: Building Social Media Workflow**
 
We built a workflow that turns an article into a LinkedIn post — text only.
 
`Article → Extract → Understand → Structure → Rewrite → Finalize → LinkedIn post`
 
**The Idea**
 
A post with a matching image gets noticed more. Let's enhance that same workflow to generate and attach an image.
 
`Article → Extract → Understand → Structure → Rewrite → Generate Image → Finalize → LinkedIn post`
 
**Updated Steps**
 
| # | n8n node | What it does |
|---|---|---|
| 1 | Google Sheets Trigger | Starts on a new article link *(had it)* |
| 2 | Google Gemini | Summarizes the article *(had it)* |
| 3 | Google Gemini | Writes the LinkedIn post *(had it)* |
| 4 | Google Gemini | Writes an image prompt *(new)* |
| 5 | HTTP → FLUX.1 [schnell] | Generates the image *(new)* |
| 6 | Download | Saves the image file *(new)* |
| 7 | LinkedIn | Posts the text AND the image |
 
A text model writes the prompt · an image model makes the picture.

## How Image Generation Models Work

### Core Training Process

- Image generation models learn by looking at millions of pictures
- While text-based AI systems learn from written content

### Input Processing

- **Text prompts**
    - The system tries to generate images that align with text prompts
- **Existing Images**
    - When you input existing images, the system modifies them to match your chosen style or concept

### Top Architectures Behind Image Generation

- **Diffusion Models**
    - Start with noise and gradually refine it into a clear image
- **GAN (Generative Adversarial Network)**
    - Two AI systems compete - one creates images, one judges if they're real
- **VAE (Variational Autoencoder)**
    - Compress images into simple codes, then rebuild them from those codes
- **Transformer-based Models**
    - Focus on how different parts of an image relate to each other

---
 
## Diffusion Models

- Diffusion models are one of the top choices for creating high-quality images from text descriptions

### How Diffusion Models Work

Let's understand the magic behind diffusion models! 

These power most modern AI image generators, such as **Stable Diffusion** and **Flux AI**
 
- Imagine you're looking at TV static - just random dots and noise
- Now imagine if you could slowly "clean up" that static, bit by bit, until it becomes a beautiful picture
- That's exactly how diffusion models work!

**Phases of Diffusion Models**
 
<details>
<summary><strong>1.Training Phase (Teaching the AI)</strong></summary>

- The AI learns by taking millions of real images
- It gradually adds "noise" to them (like adding static to a TV channel)
- It learns the reverse process: how to remove that noise step by step
</details>
<details>
<summary><strong>2.Generation Phase (Creating New Images)</strong></summary>

- Start with pure random noise (like TV static)
- The AI uses what it learned to gradually "denoise" this random pattern
- With each step, it removes a bit of noise and adds meaningful details
- After many steps (usually 20-50), you get a clear, beautiful image!
- AI-generated images take 10–30 seconds because the AI cleans random noise step by step into the clear, beautiful image!
</details>

**The Two Phases**
 
| | Training (done once) | Generation (every prompt) |
|---|---|---|
| **Direction** | Adds noise (forward) | Removes noise (reverse) |
| **Starts with** | A real image | Pure random noise |
| **What happens** | Add noise; learn to spot it | Remove noise; add detail |
| **Ends with** | A model that can denoise | A brand-new image |


# Introduction

In this unit, we will learn how to access free, powerful computing resources through **cloud platforms**, specifically focusing on **Kaggle** as our primary workspace.

---

## Hardware Reality: Understanding the Requirements

Modern AI models, whether for generating images, processing audio, or creating videos, require significant computational resources that go far beyond typical everyday computing needs.

### What AI Models Need to Run

To run AI models, you need:

- GPU with 6-16GB VRAM
- 16-32GB RAM
- Fast Storage
- Stable Compute Environment



**The truth**: Most personal computers, especially laptops, lack these specifications, particularly the specialized GPU requirements.

## The Solution: Cloud Computing

Instead of buying expensive hardware, we can **rent powerful computers over the internet** through cloud platforms.

---

## Cloud Platforms: Your Gateway to Powerful Computing

### What is Cloud Computing?

**Cloud computing** delivers IT resources over the internet on-demand. Instead of owning physical hardware, you access computing power, storage, and applications through the web.

### IT Resources

**IT Resources** are the technical components that facilitate effective functioning of technology:

- **Servers**: Powerful computers that run applications and store data
- **Databases**: Organized collections of data that can be accessed and managed
- **Storage**: Space to save files, images, models, and outputs
- **Networking**: Infrastructure for transferring data between systems

In cloud computing, all of these are available instantly through the internet, without needing to physically own or maintain them.

### On-Demand Delivery: The Key Advantage

The "on-demand" aspect of cloud computing is what makes it powerful:

✓ **Need Higher Storage?** Instantly increase storage space without buying new hard drives

✓ **Need More RAM?** Switch to a machine with 64GB RAM with a few clicks

✓ **Need Faster GPU?** Access machines with professional-grade graphics cards immediately

✓ **Need It for Just 2 Hours?** Pay only for what you use, no long-term commitment

---

## Popular Cloud Platforms for AI

Several cloud platforms provide access to powerful computing resources for AI work:

- Kaggle
- Google Colab
- RunPod
- Lambda Labs
- RunPod
- Vast.AI
- Paperspace
- Hugging Face Spaces

---

## Why We Choose Kaggle

Among all these platforms, **Kaggle stands out as the best option for cloud computing**, especially for beginners. Here's why:


### 1. Reliable GPU with 16GB VRAM

Kaggle provides access to **GPUs** with 16GB of VRAM.



### 2. 30 Hours of Free GPU Time Per Week

Unlike other platforms that severely limit free usage, Kaggle offers **30 hours weekly**, plenty for learning and experimentation.


### 3. No Credit Card Required

Many cloud platforms require credit card information even for free tiers. **Kaggle doesn't**, just sign up with email and phone verification.


### 4. Stable Connection

Kaggle's infrastructure is backed by Google, ensuring reliable and stable connections.


### 5. Pre-Installed Python Environment

Kaggle comes with **Python, Jupyter notebooks, and common AI libraries already installed**.


---

## Setting Up Your Kaggle Environment

Let's walk through the complete setup process. The setup process involves four main steps:

**Step 1**: Create Your Kaggle Account  
**Step 2**: Verify with Your Phone Number  
**Step 3**: Create a New Notebook  
**Step 4**: Configure GPU Settings  

Let's go through each step in detail.



### Step 1: Create Your Kaggle Account

<details>
<summary><strong>Account Creation Process</strong></summary><br>

**Navigate to Kaggle Website**

1. Open your web browser
2. Go to <a href="https://www.kaggle.com" target="_blank">www.kaggle.com</a> 
3. Click on `Register` button

**Complete Your Profile**

After initial registration:

1. Username: Choose a unique username (cannot be changed later)
2. Profile Information: Add optional bio and profile picture
3. Interests: Select topics you're interested in (optional)
4. Click `Complete Registration`

</details>

---

### Step 2: Verify with Your Phone Number

<details>
<summary><strong>Phone Verification Process</strong></summary><br>

1. **Navigate to Account Settings**
   - Click on your profile picture (top-right corner)
   - Select `Settings` from dropdown menu

2. **Find Phone Verification Section**
   - Look for `Phone Verification`
   - Click `Verify Phone Number`

3. **Enter Your Phone Number**
   - Select your country code from dropdown
   - Enter your mobile number (without country code)
   - Example: For India +91, enter: `9876543210`

4. **Receive Verification Code**
   - Click `Send Code`
   - You'll receive an SMS with 6-digit code
   - Code usually arrives within 30 seconds

5. **Enter Verification Code**
   - Type the 6-digit code in the verification box
   - Click `Verify`
   - ✓ You should see `Phone Verified Successfully` message

**Important Notes**:

- Without phone verification, you `cannot access GPU`
- Each phone number can verify only one account
- If you don't receive SMS, check your phone signal and try again

</details>

---

### Step 3: Create a New Notebook

<details>
<summary><strong>Notebook Creation Process</strong></summary><br>

Kaggle uses **Jupyter Notebooks**, interactive coding environments where you can write code, see results, and document your work all in one place.


1. **Access Notebook Creation**
   - From Kaggle homepage, click `Create` button (top navigation)
   - Select `New Notebook` from dropdown menu

2. **Notebook Interface Overview**
   
   When your notebook opens, you'll see:
   
   ``Code Cells`: Where you write Python code
   
   ```
   # This is a code cell
   print("Hello, Kaggle!")
   ```

</details>

---

### Step 4: Configure GPU Settings

<details>
<summary><strong>Enabling GPU Access</strong></summary><br>

By default, Kaggle notebooks run on CPU only. You must **manually enable GPU** to access the graphics card.

1. **Open Settings Panel**
   - Look for `Settings` button on the right sidebar
   - Or click three dots menu ⋮ on the right
   - Select `Settings` from options

2. **Find Accelerator Option**
   - In settings panel, look for `Accelerator` section
   - You'll see options: None, GPU, TPU

3. **Select GPU**
   - Click on the dropdown menu under `Accelerator`
   - Select `GPU` from the list 

4. **Confirm GPU is Active**
   - After selecting GPU, look for `GPU Quota` indicator
   - Should show something like `29:45 remaining this week`
   - Top-right corner should display `GPU: On` badge



#### **Additional Settings to Configure**

**Persistence**:

- Turn on `Persistence` to save files between sessions
- Files in `/kaggle/working/` directory are saved

**Internet**:

- Enable `Internet` if you need to download models or data
- Required for installing packages

</details>

---

### Step 5: Run Your Code!

<details>
<summary><strong>Testing Your Setup</strong></summary><br>

Now that everything is configured, let's test that your environment is working correctly.

1. Click inside the cell with your code
2. Press `Shift + Enter` or click ▶ `Run` button
3. Wait a few seconds for output



**If you see errors**:

- Check that your notebook has internet enabled
- Restart the notebook: Session → Restart
- Try running the test cell again

</details>

---

## Session Management: Important Notes

Understanding how Kaggle sessions work is crucial for efficient use of your free GPU time.

### Session Duration Limits

<details>
<summary><strong>12-Hour Maximum Session Length</strong></summary><br>

**Rule**: Kaggle sessions automatically stop after **12 hours of continuous runtime**.

</details>

<details>
<summary><strong>Auto-Stop After Inactivity</strong></summary><br>

**Rule**: Sessions automatically stop after approximately **40 minutes of inactivity**.

**Pro Tip**: Kaggle is smart enough to keep running if code is executing, so long generation tasks won't be interrupted.

</details>

<details>
<summary><strong>Work is Always Saved</strong></summary><br>

**Good News**: Your notebook code and saved files are preserved even after session stops.


</details>

---

## GPU Time Management: Maximizing Your 30 Hours

Kaggle provides 30 hours of GPU time per week. Here's how to make the most of it:

### Understanding GPU Quota

<details>
<summary><strong>Weekly Reset Schedule</strong></summary><br>

**Reset Time**: Every **Saturday at 5:30 AM IST** (Indian Standard Time)


</details>

<details>
<summary><strong>Monitoring Your Usage</strong></summary><br>

**Where to Check Remaining Hours**:

**Method 1**: Notebook Interface

- Look at top-right corner when GPU is on
- Shows something like "GPU: On (27:15 remaining)"

**Method 2**: Account Settings

- Click profile picture → Settings
- Find "GPU Quota" section
- Shows detailed usage breakdown

**What the Display Tells You**:

```
"28:45 remaining this week"
↓
You have 28 hours and 45 minutes left until Saturday reset
```

**Best Practices**:

- Check quota before starting large projects
- Don't start 5-hour task with only 2 hours remaining
- Leave buffer time for unexpected needs

</details>

<details>
<summary><strong>Turn Off GPU When Not Actively Using</strong></summary><br>

**Important Rule**: GPU time counts even when you're not running code if GPU is enabled.

**How to Save GPU Time**:

**1. Disable GPU for Non-GPU Work**

   - If writing code, planning, or debugging (not generating images)
   - Switch Accelerator back to "None"
   - GPU time stops counting immediately

**2. Stop Session When Done**

   - Don't leave notebook running in background
   - Click: Session → Stop Session
   - Or just close browser tab (session auto-stops after 40 min)

**3. Enable GPU Only for Generation**

   - Turn on GPU when actually generating images
   - Turn off after generation completes
   - This can save 5-10 hours per week!


</details>

---

## Troubleshooting Common Issues

Even with proper setup, you might encounter some issues. Here's how to solve the most common problems:

<details>
<summary><strong>Issue 1: No GPU Available</strong></summary><br>

**Problem**: When you try to enable GPU, the option is greyed out or shows "Not available."

**Solution**: Verify Phone Number
</details>

<details>
<summary><strong>Issue 2: Session Disconnected</strong></summary><br>

**Problem**: Your notebook session suddenly stops or shows "Session crashed."

**Solution**: Normal 12-Hour Limit

**If session ran for ~12 hours**: This is expected behavior
</details>

<details>
<summary><strong>Issue 3: Out of GPU Hours</strong></summary><br>

**Problem**: Message shows "GPU quota exceeded" or "0:00 remaining this week."



**Solution**: Wait for Weekly Reset

**Timeline**:

- Reset happens every Saturday at 5:30 AM IST

</details>

<details>
<summary><strong>Issue 4: Notebook Running Slow</strong></summary><br>

**Problem**: Code executes very slowly, images take forever to generate.

**Solution**: Enable GPU usage

</details>

---

# Mastering Image Generation with Stable Diffusion

In the previous unit, we learned about **AI Image Generation fundamentals** and how diffusion models work to create images from text descriptions. In this unit, we will focus on **Stable Diffusion**, an open-source image generation model that you can run yourself, and learn how to control it to create exactly the images you want.

---

## Stable Diffusion: An Open-Source Model

Stable Diffusion is a powerful, free AI image generation model that you can download and run on your own computer. Unlike paid services, it gives you unlimited generations and complete creative control.

### Why Choose Stable Diffusion?

Running Stable Diffusion yourself offers several key advantages over using commercial AI image platforms:

- **100% Free**: No subscriptions, no payment plans, no hidden costs
- **Unlimited Generations**: Create as many images as you want, whenever you want
- **Complete Control**: Adjust every single setting to get exactly what you need
- **Customizable**: Train it on your own style and preferences
- **Privacy**: Your creations stay private and secure on your machine
- **Learning**: Understand the real technology behind AI image generation

### Stable Diffusion Versions

Stable Diffusion has evolved through several versions, each with different strengths:

<details>
<summary>**Stable Diffusion v1.5**</summary>

- Perfect for beginners
- Works on basic computers with less powerful GPUs
- Huge community support with thousands of tutorials
- Professional quality output
- Best resolution: 512 × 512 pixels

</details>

<details>
<summary>**Stable Diffusion XL**</summary>

- Understands instructions better
- Needs a stronger computer to run smoothly
- Cutting-edge image quality
- Best resolution: 1024 × 1024 pixels
- More detailed and realistic results
</details>

<details>
<summary>**Stable Diffusion 3.5**</summary>

- Latest and most advanced version
- Best at rendering text in images
- Great for creating posters, memes, and designs with words
- Requires powerful hardware
</details>

### Platforms Providing Open Source Image Generation Models

While you can run Stable Diffusion on your own computer, several online platforms offer access to it and other open-source models:

- Hugging Face Spaces
- CivitAI
- DreamStudio
- Tensor.Art
- NightCafe

### Challenges with Online Platforms

While convenient, online platforms for AI image generation come with several limitations:

- **Costs Add Up**: Credit systems and subscriptions become expensive over time
- **Daily Limits**: Most free tiers restrict how many images you can generate per day
- **Privacy Concerns**: Your prompts and generated images are stored on their servers
- **Limited Customization**: You can't adjust advanced settings or use custom models
- **No Full Control**: You're dependent on their servers and rules

### Let's Run the Model Ourselves!

Running Stable Diffusion yourself eliminates all these limitations. Here's what you can do:

✓ **Generate Unlimited Images**: Create as many as you want, no daily caps  
✓ **Create Custom Styles**: Train the model on your preferred artistic style  
✓ **Experiment with Latest Models**: Try cutting-edge models as soon as they're released  
✓ **Keep Creations Private**: Everything stays on your computer  
✓ **Understand Real Technology**: Learn how AI image generation actually works  

---

## Setting Up Your Own Stable Diffusion

### What Are We Going to Do?

The process of running Stable Diffusion yourself involves four main steps:

**Step 1**: Set Up the Cloud Workspace  
**Step 2**: Installing Control Center  
**Step 3**: Connect All Components  
**Step 4**: Run The Model

---

### Step 1: Set Up the Cloud Workspace

**The Challenge: GPU Requirement**

Running an image generation model requires a **GPU (Graphics Processing Unit)**. This is a special computer chip designed for processing images and videos quickly.

**Problem**: Most regular computers don't have powerful enough GPUs to run Stable Diffusion smoothly.

**Solution**: Use free cloud GPU access through platforms like **Kaggle**.

### What is Kaggle?

Kaggle is a platform for data science and machine learning that provides:

- **Free GPU access** for running AI models
- **Cloud-based notebooks** (like online coding environments)
- **No installation required** on your personal computer
- **Limited weekly hours** but enough for learning and experimentation

<MultiLineNote>
<a href="https://learning.ccbp.in/course?c_id=b9811b34-585b-47e0-a0be-65f1081a74f2&s_id=04b5d8ae-3e91-4215-be28-63ec61554c26&t_id=4915a7b0-b8d7-4148-8914-d8d3fb086944" target="_blank">Kaggle Setup</a>
<br>
<a href="https://www.kaggle.com/code/contentgenai/mastering-image-generation-with-stable-diffusion/edit/run/268462724" target="_blank">Mastering Image Generation Notebook</a>

**CHECK BEFORE PROCEEDING**: Make sure your Kaggle notebook is ready and running with GPU enabled.
</MultiLineNote>
---

### Step 2: Installing Control Center (Automatic1111)

Running Stable Diffusion directly requires:

- **Coding expertise** in Python
- **Complex terminal commands** that are error-prone
- **No visual preview** of your images as they generate
- **Difficult troubleshooting** when things go wrong

This makes it difficult for beginners and time-consuming even for experts.

**Solution**: Automatic1111 WebUI

**Automatic1111** is a user-friendly web interface that acts as a control panel for Stable Diffusion. 

### Understanding Automatic1111

Instead of typing complex code commands, Automatic1111 lets you:

- **Move sliders** to adjust settings visually
- **Click buttons** to generate images instantly
- **See results immediately** on screen in your browser


### Why Choose Automatic1111?

Among various Stable Diffusion interfaces (ComfyUI, Fooocus, Hugging Face Diffusers), Automatic1111 stands out because:

✓ **Simple, User-Friendly Interface**: Clean layout, easy to understand  
✓ **Packed with Features**: Supports all major Stable Diffusion capabilities  
✓ **Extensions Available**: Add new features like better face generation  
✓ **Strong Community Support**: Thousands of tutorials and help resources  


---

### Step 3: Connect All Components

At this point:

- Stable Diffusion is installed on Kaggle's cloud machines
-  Automatic1111 is running on those remote machines
- **But these are located remotely in a data center somewhere**

**We need a way to access and control them from our own computers.**

**Solution**: Ngrok

**Ngrok** creates a secure, temporary URL that acts as a bridge between your browser and Kaggle's cloud computers.


### Setting Up Ngrok

<details>
<summary><strong>Create Ngrok Account</strong></summary><br>

1. Visit <a href="https://ngrok.com" target="_blank">ngrok.com</a>
2. Sign up with your email or Google account
3. Verify your email address
4. Log in to your Ngrok dashboard

</details>

<details>
<summary><strong>Get Your Auth Token</strong></summary><br>

1. After logging in, go to "Your Authtoken" section
2. Copy the authentication token (looks like: `2a1b3c4d5e6f7g8h9i0j`)
3. Keep this token safe - you'll need it in the next step

**Important**: Never share your auth token publicly. It's like a password for your Ngrok account.

</details>

<details>
<summary><strong>Add Token to Kaggle Notebook</strong></summary><br>

1. In your Kaggle notebook, find the Ngrok configuration cell
2. Paste your auth token in the designated place
3. Run the cell to authenticate Ngrok

Example code structure:

```
!ngrok authtoken YOUR_TOKEN_HERE
```

</details>

<details>
<summary><strong>Get Your Temporary URL</strong></summary><br>

1. Run the cell that starts Ngrok tunnel
2. Look for output that shows a URL like: `https://abc123.ngrok.io`
3. Copy this URL - this is your personal gateway to Automatic1111

**Note**: This URL is temporary and changes each time you restart your notebook.

</details>

### Summary: How It All Connects

Here's what happens once everything is set up:

**1. Run Once**  
You execute your Kaggle notebook cells

**2. Automatic1111 Starts**  
The web interface launches on Kaggle's cloud machine

**3. Ngrok Generates Link**  
A unique web URL is created (e.g., `https://abc123.ngrok.io`)

**4. Open in Browser**  
You paste that URL in any browser, on any device

**5. Generate AI Art**  
You can now create images from anywhere with internet access!

---

### Step 4: Run The Model

Once you've opened your Ngrok URL in a browser, you'll see the Automatic1111 interface. It has several tabs:

- **txt2img**: Create images from text descriptions (main tab)
- **img2img**: Modify existing images
- **Extras**: Upscale and enhance images
- **Settings**: Configure the interface

For now, we'll focus on the **txt2img** tab, where all the main controls are.

---

## Understanding Each Control

The Automatic1111 interface has many settings that control how your images are generated. Understanding these controls is key to creating exactly what you want.

Here are the essential controls you'll use:

- **The Prompt Box**: Your main instruction to the AI
- **Negative Prompt**: What to avoid in the image
- **Seed Number**: For consistent results
- **CFG Scale**: How closely AI follows your prompt
- **Sampling Steps**: Image quality and refinement
- **Sampling Method**: Speed vs quality trade-off
- **Image Size**: Resolution of the output
- **Batch Count**: How many variations to generate

---

### The Prompt Box: Your Main Instruction

The prompt box is where you tell the AI what image you want to create. This is your primary way of communicating with Stable Diffusion.

**Problem**: *"How do I tell the AI what I want?"*

**Solution**: Write a detailed description using clear, descriptive language.


---

### Negative Prompt: What to Avoid

The negative prompt tells the AI what NOT to include in your image. This helps prevent common problems like blurry faces, extra fingers, or unwanted styles.

**Problem**: *"The AI keeps adding things I don't want!"*

**Solution**: List unwanted elements in the negative prompt box.

---

### Seed Number: For Consistent Results

The seed is a number that controls the randomness in image generation. Using the same seed with the same prompt always produces the same image.

**Problem**: *"I want to generate the exact same image again!"*

**Solution**: Use a specific seed number instead of random (-1).


---

### CFG Scale: How Closely AI Follows Your Prompt

CFG (Classifier Free Guidance) Scale controls how strictly the AI follows your prompt instructions.

**Problem**: *"My image doesn't match my prompt!"*

**Solution**: Adjust the CFG Scale to control adherence to your instructions.

---

### Sampling Steps: Control Image Quality

Sampling steps determine how many times the AI refines the image. More steps = more refinement = better quality (but slower generation).

**Problem**: *"My image looks rough or unfinished!"*

**Solution**: Increase the sampling steps for more refined results.

---

### Sampling Method: Choose Your Style or Speed

Sampling methods are different algorithms (mathematical approaches) the AI uses to generate images. Each method has trade-offs between speed, quality, and consistency.

**Problem**: *"I want different styles or faster results!"*

**Solution**: Choose a sampling method based on your priorities.

**Common Sampling Methods**

<details>
<summary>Euler a (Euler Ancestral)</summary><br>

- **Speed**: Very Fast
- **Quality**: Good, slightly rough
- **Consistency**: High randomness between seeds
- **Best for**: Quick experiments, artistic variety

**Characteristics**: Adds creativity and randomness, produces more varied results

</details>

<details>

<summary>DPM++ 2M Karras</summary><br>

- **Speed**: Balanced
- **Quality**: Excellent
- **Consistency**: Moderate
- **Best for**: Most general use cases (recommended)

**Characteristics**: Great balance of speed and quality, works well with 20-30 steps

</details>

<details>
<summary>DDIM</summary><br>

- **Speed**: Moderate
- **Quality**: Very consistent
- **Consistency**: Low randomness, very predictable
- **Best for**: When you need reproducible results

**Characteristics**: Same prompt and seed produce nearly identical results, good for testing

</details>

<details>
<summary>Heun</summary><br>

- **Speed**: Slow
- **Quality**: Very High
- **Consistency**: Good
- **Best for**: Final high-quality renders

**Characteristics**: Extra refinement pass per step, takes longer but produces cleaner images

</details>


---

### Image Size (Resolution)

Image size sets the width and height of your generated image in pixels. Different Stable Diffusion versions work best at specific resolutions.

**Problem**: *"I need specific image dimensions!"*

**Solution**: Set appropriate width and height based on your SD version and needs.


<details>
<summary><strong>Stable Diffusion v1.5</strong></summary><br>

**Optimal Resolution**: 512 × 512 pixels

**Why**: The model was trained on 512×512 images, so it performs best at this size.

</details>

<details>
<summary><strong>Stable Diffusion XL</strong></summary><br>

**Optimal Resolution**: 1024 × 1024 pixels

**Why**: SDXL was trained on larger images for better detail and quality.

</details>

---

### Batch Count

Batch count determines how many different images are generated at once from the same prompt. Each image will have variation due to different random seeds.

**Problem**: *"I want different versions to choose from!"*

**Solution**: Increase batch count to generate multiple variations simultaneously.

---

## Fixing Common Problems

Even with the right settings, you might encounter some common issues. Here's how to fix them:

### Problem: Wrong Art Style

**Symptoms**: Your image doesn't match the artistic style you wanted (e.g., looks like a cartoon when you wanted realistic photos).

**Fix**: Add style keywords to your prompt

<details>
<summary><strong>Style Keywords to Add</strong></summary><br>

**For Photorealistic**:

```
photorealistic, professional photography, DSLR, 4k, high resolution, detailed
```

**For Cartoon/Anime**:

```
cartoon style, anime, cel-shaded, animated, illustration
```

</details>

---

### Problem: Weird Hands or Faces

**Symptoms**: Generated people have deformed hands, extra fingers, asymmetrical or distorted faces.

**Why It Happens**: Stable Diffusion struggles with complex anatomical details like hands and faces.

**Fix**: Add specific terms to your negative prompt

<details>
<summary><strong>Negative Prompt for Anatomy</strong></summary><br>

```
bad hands, deformed face, extra fingers, missing fingers, fused fingers, mutated hands, poorly drawn hands, poorly drawn face, deformed eyes, bad anatomy, bad proportions, extra limbs, cloned face, disfigured, gross proportions, malformed limbs
```

</details>

---

### Problem: Blurry or Unclear Images

**Symptoms**: Images lack detail, look soft or out of focus, poor quality overall.

**Fix**: Adjust quality-related parameters

<details>
<summary><strong>Settings for Sharper Images</strong></summary><br>

**1. Increase Sampling Steps**

- Change from 20 to 30 or 35 steps
- More refinement passes = clearer details

</details>

---

### Problem: Generation is Too Slow

**Symptoms**: Each image takes several minutes to generate, workflow feels sluggish.

**Fix**: Optimize your settings for speed

<details>
<summary><strong>Speed Optimization Tips</strong></summary><br>

**1. Lower Resolution**

- Use 512×512 instead of 768×768 or larger
- You can always upscale later

**2. Reduce Sampling Steps**

- Drop from 30 to 20-25 steps
- Quality difference is often minimal

</details>

---


# Introduction to AI Agents

In the previous units, we learned about AI tools like ChatGPT Agents and we learned about building automated workflows using n8n and integrating AI for tasks like content creation and summarization. In this unit, we'll explore AI Agents — intelligent systems that can think, plan, and take actions autonomously to achieve specific goals.

## Introduction to AI Agents

- An AI agent is a system that can operate independently to achieve a specific goal without constant human intervention

AI Agents can:

1. **Understand** what you want
2. **Reason** and plan how to accomplish the task
3. **Execute** actions on our behalf
4. Learn from **success** and **failures**

### Understanding with Analogy

Let’s understand with a babysitter analogy

- When parents leave a child with a babysitter, they provide:
    - Basic instructions (bedtime, emergency contacts)
    - Resources (food, phone numbers)
    - The overall mission (keep the child safe and happy)
- They don’t micromanage; the babysitter uses judgment to handle situations.”

### Why Agents Are Needed

- To solve complex tasks
- Learn user preferences and tailor approach
- Need for autonomy

---

## Core Components

- AI Model (like GPT-5 or Claude)
- Tools (search engines, databases)
- Memory

### AI Model - LLM

- The model is essentially the agent’s “brain” – it interprets instructions, reasons about problems, and decides on actions (GPT-5, Claude, Llama, etc)
- The "brain" of the agent that can do
    - Goal Understanding
    - Planning & Reasoning
    - Adaptive Learning
    - Learning

### Tools

- Tools are external functions or interfaces the agent can use to interact with the outside world
- Tools are the agent's "arms and legs".
    - Extends Capabilities: Allow the agent to perform actions it couldn't do alone
    - Access Real-Time Data: Connect to current information beyond the model's training cutoff
    - Executes Specific Functions: Perform specialized tasks with precision

**Commonly Used Tools**
 
- **Web Search**       Allows the agent to fetch up-to-date information from the internet 
- **Image Generation** Creates images based on text descriptions 
- **Retrieval**        Retrieves information from an external source 
- **API Interface**    Interacts with an external API (GitHub, YouTube, Spotify, SERP API etc.) 

### Memory

- Memory allows the agent to
    - Store information
    - Learn from past interactions
    - Maintain context and  continuity

---

## How Agents Work

- Agents operate in a continuous loop that integrates the components
- Some of the commonly used Frameworks are:
    - ReAct
    - Tool Use
    - Reflection

### ReAct - Reasoning and Acting

One of the most commonly used patterns is:

- Thought / Reason
- Action
- Observation

**Thought**

- The agent receives information
- Understands the information
- Reasons and decides the next steps based on the observation

**Action**

- The agent identifies a specific action
- Uses an appropriate tool to perform that action

**Observation**

- Agent evaluates the outcome of its action
- Compares it with expected results
- Refines understanding and approach based on feedback

### Common Pattern - ReAct

- The ReAct pattern involves three main stages — *Thought, Action,* and *Observation* — which repeat in a loop.  
- This allows the agent to reason through problems, perform actions, observe outcomes, and refine its approach until it reaches the final **Answer**.

### Example

- Let’s say you have to book a travel vacation to Ooty

**Planning Travel Vacation - Human  **

- Opening Booking App
- Searching for flights
- Searching for Hotels
- Choosing Best Options
- Booking Flight

**Booking a Travel Vacation**

Think of an AI agent as a smart helper that can work on its own to get things done

- ` Define Goal`: 
    Set the objective for the AI agent
- `Execute Task`: Autonomously performs necessary actions 
- `Complete Booking`: Vacation bookings are successfully finalized 

**Example: **

`Plan a vacation to Ooty for three people with a budget of 20,000 INR`

<details>
<summary><b>Loop 1: Initial Assessment</b></summary>

#### Thought
I need to plan a vacation to Ooty for three people with a focus on budget, food, and activities.

#### Action
Search for **“Average cost breakdown for Ooty vacation from major Indian cities.”**

#### Observation
Transportation from major cities costs around **50–300 INR per person.**

</details>

<details>
<summary><b>Loop 2: Transportation Planning</b></summary>

#### Thought
Transportation will be a significant portion of the total cost based on the starting location.



#### Action
Search for **"Cheapest transportation to Ooty from Bangalore/Chennai/Delhi."**


#### Observation
From Bangalore: Bus (1,800 INR round-trip for three) + additional expenses — exceeds budget allocation.

</details>

<details>
<summary><b>Loop 3: Accommodation Research</b></summary>

#### Thought
With approximately 7,000 INR remaining for accommodation, the budget allows for about 2,300 INR per night.



#### Action
Search for **"Budget hotels in Ooty under 2,500 INR with good reviews."**



#### Observation
Several options available: around 2,000–2,300 INR per night with an average rating of 8.5/10.

</details>

<b>Agent Outcome</b>

- Day-wise itinerary
- Booked flights and hotels
- Budget breakdown
- Travel and food recommendations
- Reminders and confirmations


# Mastering AI Audio Generation

In this unit, we will explore **AI Audio Generation**, a technology that uses artificial intelligence to create sounds, music, speech, and audio effects from simple text prompts or reference samples. We will learn about different types of audio generation, explore various models and platforms, and build a practical **AI Podcast Generator using Murf.ai**.

---

## AI Audio Generation

AI Audio Generation is the use of artificial intelligence to create sounds, music, speech, and audio effects from simple text prompts or reference samples.




### Audio Generation: Traditional vs AI

The way we create audio has changed dramatically with AI technology. Here's how traditional methods compare to AI-powered generation:

<details>
<summary><strong>Traditional Audio Generation</strong></summary><br>

**Challenges**:

- **Expensive Equipment Needed**: Professional microphones, recording studios, sound editing software
- **Years of Training Needed**: Musicians need years to master instruments, voice actors need training, sound engineers need expertise

</details>

<details>
<summary><strong>AI-Powered Audio Generation</strong></summary><br>

**Advantages**:

- **Simple Text Description**: Just type what you want
- **Quick and Cost-Effective**: Generate audio in seconds or minutes

</details>

---

### Examples in Daily Life

AI audio generation is already part of our everyday lives. You interact with it more often than you might realize:

<details>
<summary><strong>Communication Tools</strong></summary><br>

- **Google Translate**: Speaks translated text in different languages
- **Voice Messages**: Voice typing converts your speech to text in messaging apps
- **Smart Speakers**: Alexa, Google Assistant, Siri respond with AI-generated voices

</details>

<details>
<summary><strong>Reading and Learning</strong></summary><br>

- **iPhone/Android Reading Mode**: Reads articles and web pages aloud
- **Kindle/Audible**: Text-to-speech for books and documents
- **YouTube Auto-Generated Narration**: Automatically reads video descriptions

</details>

<details>
<summary><strong>Content and Accessibility</strong></summary><br>

- **Video Subtitles**: Automatically generates captions from speech
- **GPT Navigation**: Voice output for AI chatbot responses
- **Smart Home Commands**: Voice recognition and response systems

</details>

---

### Real World Use Cases Across Industries

AI audio generation is transforming multiple industries by making audio creation accessible, fast, and cost-effective.


<details>
<summary><strong>Educational Applications</strong></summary><br>

### Lecture Transcription
Converting classroom lectures and educational videos into written text for students to review and study.

### Automated Note-taking
AI listens to lectures and automatically creates organized notes for students.

### Real-time Translation
Translating lectures and educational content into different languages instantly, making education accessible globally.

### Captioning of Virtual Classes
Automatically generating subtitles for online classes, helping students with hearing disabilities and language barriers.

### Audio and Video Summarization
Creating short audio summaries of long lectures and educational videos, helping students review key points quickly.

</details>



<details>
<summary><strong>Film and Entertainment Applications</strong></summary><br>

### Animated Movies
Generating character voices without needing voice actors for every role, or creating voices for fantastical creatures.

### Dubbing
Translating movie dialogue into different languages while maintaining the original voice characteristics and emotions.

### Music
Creating background scores, sound effects, and musical compositions for films without hiring full orchestras.

</details>


<details>
<summary><strong>Content Creation Applications</strong></summary><br>

### YouTube and TikTok Videos
Generating voiceovers for video content, educational tutorials, and social media posts without recording your own voice.

### Podcasts
Creating complete podcast episodes from scripts, with natural-sounding voices and proper pacing.

### Audiobooks
Converting written books into audio format, making literature accessible to people who prefer listening over reading.

</details>


<details>
<summary><strong>Healthcare Applications</strong></summary><br>

### Managing Documentation
Converting doctor's verbal notes into written medical records automatically, saving time and reducing errors.

### Patient Engagement
Creating audio instructions for patients about medication, treatment plans, and health guidance in multiple languages.

</details>

---

## AI Audio Generation Types and Models

AI audio generation works through different transformation processes. Understanding these types helps you choose the right tool for your needs.

### Three Transformation Types

<details>
<summary>**Text-to-Speech (TTS)**</summary>

Takes text descriptions as input and generates natural sounding audio as output.


**Use Cases**:

- Creating voiceovers for videos
- Generating audiobooks
- Voice assistants responding to queries
- Making content accessible for visually impaired users

</details>


<details>
<summary>**Speech-to-Text (STT)**</summary>

Converts spoken words into written text.

**Use Cases**:

- Transcribing meetings and interviews
- Creating subtitles for videos
- Voice typing in messaging apps
- Converting lectures into notes
</details>


<details>
<summary>**Speech-to-Speech (STS)**</summary>

Enables real-time voice conversations, even across different languages.

**Use Cases**:

- Real-time translation in calls
- Voice cloning and modification
- Dubbing movies into different languages
- Creating different voice variations
</details>

---

## Open Source Models

Open source AI audio models are freely available for anyone to use, modify, and integrate into their projects. Here are the popular open source models:


| Model Name | Company/Creator |
|-----------|----------------|
| **Whisper** | OpenAI |
| **MeloTTS** | MyShell |
| **F5-TTS** | SWivid |
| **KokoroTTS** | Hexacode |
| **AudioCraft/MusicGen** | Meta |
| **OpenVoice V2** | Replicate |
| **Whisper + SpeechT5 S2S** | Replicate |
| **Bark** | Suno |

and many more models available in the open source community.

---

## Popular Audio Generation Models: Open Source

### Demo: Speech to Text

**Use Case**: Converting spoken audio into written text.

**How It Works**:

1. Upload or record audio file
2. AI model processes the speech
3. Generates accurate text transcription
4. Download or copy the text

**Example Models**: Whisper, SpeechT5

<details>
<summary><strong>Handson</strong></summary><br>

<a href="https://huggingface.co/spaces/Xenova/whisper-web" target="_blank">Whisper</a>
<br>
<a href="https://s3.ap-south-1.amazonaws.com/new-assets.ccbp.in/frontend/loading-data/niat_programming_foundations/niat_coding_questions/A%20one%20minute%20TEDx%20Talk%20for%20the%20digital%20age%20%20Woody%20Roseland%20%20TEDxMileHigh.mp3" target="_blank">Audio File</a>

</details>

---

### Demo: Text to Speech



**How It Works**:

1. Input the text you want to convert
2. Select voice characteristics (gender, accent, tone)
3. AI generates natural-sounding speech
4. Download the audio file

<details>
<summary><strong>Handson</strong></summary><br>

<a href="https://huggingface.co/spaces/neuromod0/MeloTTS-English-v3" target="_blank">MeloTTS</a>
<br>

**Sample Text**:

```
Artificial Intelligence (AI) revolutionizes the way we live and work through machine learning, natural language processing, and computer vision.

From ChatGPT to self-driving cars, AI systems analyze vast data, recognize patterns, and make decisions.

While offering unprecedented opportunities in healthcare, education, and automation, AI also raises important ethical considerations about privacy, bias, and job displacement.
```

</details>

---

## Closed Source Models

Closed source models are proprietary AI systems developed and maintained by companies. They are not freely available for modification but can be accessed through APIs or platforms.


| Model Name | Company |
|-----------|---------|
| **FastSpeech2** | Microsoft |
| **Tacotron 2** | Google |
| **NTTS (Neural Text-to-Speech)** | Amazon |
| **WaveNet** | Google DeepMind |
| **Chirp** | Google |
| **VALLE** | Microsoft |

and many more proprietary models.

**Note**: These models typically offer higher quality and more natural-sounding output but require subscriptions or API access.

---

## Popular Audio Generation Platforms

Instead of working directly with models, many platforms provide user-friendly interfaces for AI audio generation.

<details>
<summary>**Speech Generation Platforms**</summary>

- ElevenLabs
- Murf.ai
- OpenAI Whisper
- AssemblyAI
- Google Speech-to-Text
- Rev
- Deepgram
- Speechify
</details>

<details>
<summary><strong>Handson</strong></summary><br>
<a href="https://elevenlabs.io/" target="_blank">ElevenLabs</a>
<br>

**Text-to-Speech**:

```
Generative AI is a type of artificial intelligence that focuses on creating new content, like text, images, music, audio, and videos, rather than analyzing or classifying existing data. It does this by learning from large datasets and using its learned patterns to generate novel outputs in response to prompts or inputs
```

<a href="http://murf.ai/" target="_blank">Murf.ai</a>
<br>

**Text-to-Speech**:

```
Artificial Intelligence (AI) revolutionizes the way we live and work through machine learning, natural language processing, and computer vision. From ChatGPT to self-driving cars, AI systems analyze vast data, recognize patterns, and make decisions. While offering unprecedented opportunities in healthcare, education, and automation, AI also raises important ethical considerations about privacy, bias, and job displacement.
```


<a href="https://aistudio.google.com/live" target="_blank">Google AI Studio</a>
<br>

**Speech-to-Speech**:

```
Could you tell me what generative AI is?
```

</details>

---

## Music and Audio Generation Platforms

<details>
<summary><strong>Popular Music Generation Platforms</strong></summary><br>

- Suno
- Udio
- Aiva
- Soundful
- Hugging Face Spaces
- BandLab

</details>

---

## Building an AI Podcast Generator using Murf.ai

Now that we understand AI audio generation, let's build a practical application: an **AI Podcast Generator** that automatically creates podcast episodes from just a topic name.

### Application Overview

Our AI Podcast Generator will follow this simple flow:

**Step 1**: Type Your Topic  
**Step 2**: Generate Script  
**Step 3**: Create Voice  
**Step 4**: Get Podcast  



### Steps to be Followed

<details>
<summary><strong>Setting Up the Chat Trigger</strong></summary><br>

**What is a Chat Trigger?**

The Chat Trigger is the starting point that initiates our workflow. It allows users to input their podcast topic and start the generation process.

### Implementation Steps

**Prepare Your Workspace**:

1. Open your n8n workflow editor
2. Start with a blank canvas

**Add Chat Trigger Node**:

1. Click the `+` button to add a new node
2. Search for "Chat Trigger"
3. Select "Chat Trigger" from the results
4. The node will appear on your canvas

**How It Works**:

- User types a podcast topic in the chat interface
- The trigger captures this input
- Passes the topic to the next step for script generation

**Example Input**: "The history of artificial intelligence"

This input will be used throughout the workflow to generate relevant content.

</details>

<details>
<summary><strong>Creating the Podcast Script</strong></summary><br>

**Add Basic LLM Chain Node**

**Steps**:

1. Click `+` to add a new node after Chat Trigger
2. Search for "Basic LLM Chain"
3. Select "Basic LLM Chain" from results
4. This node will generate our podcast script

**Define Prompt for Generating Podcast Script**

The prompt is crucial as it tells the AI how to write your podcast script.

**Prompt Template**:

```
You are a professional podcast script writer.

Write a conversational and engaging podcast script on the topic: {{ $json.chatInput }}.

Keep it around 2 minutes when spoken.

Use a friendly and informative tone, as if talking directly to listeners.

Avoid any headings, labels, or formatting. Output plain text only.
```

**Prompt Breakdown**:

- **Role**: "You are a professional podcast script writer" - Sets AI's identity
- **Task**: "Write a conversational and engaging podcast script" - Clear instruction
- **Input**: `{{ $json.chatInput }}` - Takes topic from Chat Trigger
- **Length**: "Keep it around 2 minutes when spoken" - Controls output length
- **Tone**: "friendly and informative tone" - Defines style
- **Format**: "Output plain text only" - Ensures clean output for audio conversion

**Search and Add Chat Model**

**Steps**:

1. In the Basic LLM Chain node, look for the model selection
2. Click `+` to add a chat model
3. Search for "Google Gemini Chat Model"
4. Select it from the results

**Choose Model and Connect to LLM Chain**

**Configuration**:

1. Select "Google Gemini Chat Model"
2. Add your Gemini API credentials (refer to previous setup guides)
3. Connect the Chat Trigger output to the LLM Chain input
4. The LLM Chain will now receive the topic and generate a script

**What Happens**:

```
Topic: "The future of renewable energy"
    ↓
Gemini processes with the prompt
    ↓
Generates: [A 2-minute conversational podcast script about renewable energy]
```

</details>

<details>
<summary><strong>Implementing Murf.ai in the Workflow</strong></summary><br>

**Murf.ai** is an AI speech generation platform that converts your written content into natural-sounding speech.

### Exploring Murf.ai

Before implementing, explore the platform:

- Visit <a href="https://murf.ai" target="_blank">Murf.AI</a>
- Create a free account
- Test different voices and see how natural they sound
- Note the voice names you like (e.g., "en-US-natalie")

### Add HTTP Request Node

**Steps**:

1. Click `+` to add new node after LLM Chain
2. Search for "HTTP Request"
3. Select "HTTP Request" node
4. This will connect to Murf.ai's API

### Configure API Endpoint

**Configuration Details**:

**Method**: POST  
**URL**: Murf.ai API endpoint for text-to-speech  
**Authentication**: Add your Murf.ai API key

- **text**: Takes the script from Gemini LLM output
- **voiceId**: Specifies which voice to use
- **format**: Audio output format

### Set Voice to en-US-natalie

"en-US-natalie" is a natural-sounding female voice with American English accent. You can choose different voices based on your preference.

**Popular Voice Options**:

- en-US-natalie (Female, American)
- en-US-davis (Male, American)
- en-GB-oliver (Male, British)


</details>

<details>
<summary><strong>Downloading Your Podcast</strong></summary><br>

### Add Another HTTP Request Node

**Steps**:

1. Click `+` to add another HTTP Request node
2. This node will download the generated audio file

### Configure to Download the URL

**Why Two Request Nodes?**

- **First Request**: Sends text to Murf.ai for processing
- **Second Request**: Downloads the generated audio file from the URL provided by Murf.ai

**Configuration**:

**Method**: GET  
**URL**: `{{ $json.audioUrl }}` (received from Murf.ai response)  
**Response Format**: Binary (to download audio file)

### Enjoy Your Podcast

**Final Output**:

1. The workflow generates an audio file
2. Download the MP3 file to your device
3. Listen to your AI-generated podcast!

</details>

---


# Building No-Code Applications with AI

In the previous unit, we built an AI Podcast Generator that automated audio content creation using n8n and Murf.ai. In this unit, we'll focus on transforming our workflow into a real web application — a user-friendly interface that anyone can access and use without knowing anything about n8n or automation.

## Build Your Own No-Code Application

**The Challenge**

Our n8n workflows are powerful but hidden

- They run automatically inside n8n
- Only the workflow creator can see and use them
- Others can’t use them like regular apps

What if others could use our workflows like normal apps?

> **Solution**
> 
> No-Code Application Building

### What to Achieve?

We will be building a frontend application for our Podcast Generator workflow

- The Complete Flow

    - User clicks `Generate Podcast`
    2. Trigger n8n Workflow
    3. n8n processes request (Generate content & convert to audio)
    4. Send results back to UI
    5. UI displays or plays podcast


### No-Code Application Building

You might have built applications using:

- Lovable
- Bolt
- And other no-code tools
complete applications in just minutes!


### Vibe Coding

- Vibe Coding is a new way to build interfaces
- You simply describe what you want in natural language
- AI generates the complete interface for you
- Think of it like telling a designer your vision and watching it come to life

### Meet the AI Application Builders

There are 100s of tools like: 

- Replit
- Lovable 
- Base44, Claude Artifacts, V0 by Vercel, and Bolt 

---

## Building a Podcast Generator

### What We're Building

- **Frontend** : Create a beautiful interface first
- **N8n Workflow**: Update our workflow to accept requests
- **Connection**: Link them seamlessly together

### Steps to Follow

<details>
<summary>**Creating a Beautiful Frontend**</summary>
<br>

<b>Open Lovable Platform</b>

- Go to lovable.dev
- Login to the website
- Paste the prompt

<details>
<summary><b>Describe your Frontend (Prompt)**</b></summary>

```
Design a minimal and visually appealing podcast interface. The interface should feature:
A prominent text input field labeled "Type podcast topic here..." where users can enter their desired podcast topic.
A "Generate Podcast" button, incorporating a speaker emoji, that triggers the podcast generation process. The button should exhibit a color change on hover.
A loading animation (e.g., pulsing dots) displayed while the podcast is being generated.
An audio player area that initially displays "Podcast will appear here."
Functionality: Upon clicking "Generate Podcast," the loading animation should appear for 2 -3 seconds, followed by the message "Feature coming soon!" in the audio player area.
Visual Style: Utilize soft pastel colors (with appropriate contrast) and rounded corners throughout the design to create a cute and friendly appearance.
Adaptive Design: Ensure the interface is flexible and adapts seamlessly to different screen sizes.

```
</details>

<b>Test the Interface</b>

- Type some sample text
- Click the Generate Podcast button
- See the loading animation
</details>

<details>
<summary>**Connecting the Frontend to n8n Workflow**</summary>
<br>

<b>Providing Data to n8n</b>

- To generate a podcast, n8n needs information We'll send this data in a specific format.

`{"text": "whatever topic they typed"}`

<b>The Missing Link</b>
<br>
We need to create a bridge between:

- The beautiful interface (what people see) and n8n podcast generator workflow (what creates the podcast)

<b> Webhooks</b>

- A webhook serves as a bridge between the frontend application and n8n workflow by automatically receiving incoming data 

<b>WebHook Node</b>

- A webhook node act as a trigger node for a workflow when you want to receive data and run a workflow based on the data
- It is essentially a `URL endpoint` that listens for incoming data

<b>Webhooks - The Bridge Builder!</b>

- Think of a webhook like giving your workflow a phone number on the internet:

    - Your frontend knows this phone number
    - It "calls" this number with the user's text - whenever a user enters text and presses the button
    - Your workflow "answers" - processes the input and generates the podcast
    - It "calls back" with the finished audio file - returns the final result

<b>Replace Chat Trigger with Webhook</b>

<MultiLineWarning text="Why this change?">

- Chat Trigger only works inside n8n
- Webhook works from anywhere on the internet

</MultiLineWarning>
<b>**Steps to Update:</b>

1. Open your existing Podcast Generator workflow in n8n
2. Delete the Chat Trigger node
3. Add a Webhook node as the starting point
4. Configure the Webhook node settings

<b> Configuring the Webhook Node:</b>

- Open the Webhook node settings
1. Set `HTTP Method` to `POST`
3. Set `Response Mode` to `Respond to Webhook`
4. Copy the generated webhook URL (looks like: `https://your-n8n.app/webhook/abc123xyz`)

<b> How Webhooks Work </b>

- The frontend sends data to the webhook URL, and the webhook passes it to your workflow for processing

<b>Updating Data Connections</b>

- Connect Webhook to basic LLM chain node
- In LLM chain settings :
    - In the Source for Prompt (User Message), change dropdown to `Define below`
    - Update the input value to: `{{ $json.body.text }}`
- Similarly, update the System prompt placeholder to: 
    `{{ $json.body.text }}`
- This captures the text that comes from your frontend
- Keep all other connections the same

<b> Updating Data Connections</b>

- Complete Workflow Flow
    Webhook (Receives text) → LLM Chain (Processes text) → Gemini → Murf.ai

<b>Current Situation</b>

Right now, the workflow:

- Receives data from frontend
- Processes the request
- Generates podcast audio
- But the audio is stuck inside n8n!

The frontend is waiting for a response, but none has been sent yet.

<b> Send Data Back – Respond to Webhook Node</b>

- A node that completes the webhook conversation
- Takes data from your workflow
- Sends it back to whoever called the webhook

<b>Set up the Response Node</b>

- Add `Respond to Webhook` node after your HTTP Response/Podcast Downloader node
- In the node settings, configure:
    - `Respond With`: Binary File (because our output is audio)
    - `Response Data Source`: Automatically from Input
- This ensures the workflow sends the generated audio back as a downloadable file or playable URL to the frontend.


</details>

<details>
<summary>**Connecting Everything Together**</summary>
<br>

<b>Specifying Frontend Integration Details</b>

- Previously, we created a basic frontend without specifying:
    - Which webhook URL to call?
    - What data format to expect?
    - How to handle the response?

<b>Connecting the Frontend to n8n</b>

- Now we will update our frontend with the actual connection details from our n8n workflow configuration

<b>Update your Frontend</b>

- Go back to your Lovable project
- Copy your webhook URL from n8n
- Paste the connection prompt, replacing [PASTE YOUR WEBHOOK URL HERE] with your actual webhook URL
- Wait for Lovable to update the interface
- Preview the updated interface

<details>
<summary><b>Updated Prompt</b></summary>

```
Update the podcast interface to connect with this web address: [PASTE WEBHOOK URL HERE]

When someone clicks Generate Podcast:
Take the text they typed about their podcast topic
Send it to the web address in this format: {"text": "the topic they typed"}
Show loading dots saying "Creating podcast... please wait!"

When the response comes back:
It will contain {"audioFile": "link to the podcast"}
Show this audio in the player using the audioFile link
Display message " Podcast is ready! Click play to listen"

If something goes wrong:
Show "Oops! Something went wrong. Please try again"

After successful generation:
Clear the text box for next topic
Keep all the beautiful design from before
```
</details>

<b> What Happens Behind the Scenes </b>
<br>

The Complete Flow

#### 1. Frontend
- Packages the topic as JSON
- Sends data to n8n webhook

#### 2. n8n Webhook
- Receives the JSON data
- Triggers the workflow

#### 3. Audio File URL
- Workflow processes and generates audio
- Returns audio file URL

#### 4. Podcast Player
- Waits for the audio file URL
- Shows the podcast player when ready
- User can play the generated podcast

<b>Test the Complete System</b>
#### Step-by-Step Testing

- Execute the workflow in n8n (to keep it ready)  
2. Open your Lovable preview  
3. Type a podcast topic (e.g., "Generative AI")  
4. Click the `Generate Podcast` button  
5. Watch the loading animation appear  
6. Switch to the n8n tab — see nodes turning green as workflow executes  
7. Wait 10-30 seconds for processing  
8. Return to Lovable — audio player appears with your podcast  
9. Click `Play` and listen to your AI-generated podcast!

<b> Workflow Should be in Active State</b>
<br>
To ensure your workflow is automated and triggers as expected, make sure the workflow is active

- Open your workflow in n8n
- Toggle the workflow status to Active
- The workflow will now automatically respond to incoming webhook requests

<MultiLineNote>
- The Active button has been updated to Publish, allowing you to publish your workflows.
- Kindly note that the Publish feature is restricted to a limited number of uses on the portal.
</MultiLineNote>
</details>

<details>
<summary>**Deploy our Application**</summary>

- Right now, your app works in Lovable's preview
` Deployment gives it a real home on the internet where anyone can visit! `

<b>Deployment</b>

- In Lovable, click the Publish button (top right corner)
- Wait 1-2 minutes while Lovable deploys your project
- Receive your public URL (format: https://yourapp.lovable.app)
- Share the URL with friends and family!
</details>
---

### Before vs After

<b>BEFORE:</b>

- Workflow hidden inside n8n
- Only works with Chat Trigger
- Can't share with others
- Manual execution required

<b>AFTER:</b>

- Professional web application
- Beautiful public interface
- Anyone can use it
- Your own podcast generation service!"


---

# Introduction

In the previous unit we understand the core concepts of text-to-speech, speech-to-text, and speech-to-speech technologies and built a podcast generator. In this unit, we'll go beyond the basics and explore how to add emotion and nuance to our AI-generated audio using F5-TTS.


## Mastering AI Audio Generation using F5-TTS


### What We’ve Explored So Far

We have looked at various closed and open-source audio generation models, including online platforms like ElevenLabs and Murf AI.

### Challenges with Third-Party Providers

While convenient, these services come with challenges:

- **Costs**: Subscription fees can add up.
- **Limited Customization**: You have less control over the final output.
- **Daily Limits**: Many services restrict the amount of audio you can generate.
- **No Full Control**: You are dependent on the provider's infrastructure.
- **Privacy Concerns**: Your data is processed on external servers.

What if the same powerful AI audio generation model could run on your own machine, without external providers? This is where open-source models come in.

### Open Source Audio Generation Models

- F5-TTS
- MeloTTS
- Whisper
- OpenVoice V2
- …and many more

## Introducing F5-TTS

F5-TTS is an AI-powered text-to-speech synthesis tool that converts text into natural-sounding speech. It offers real-time processing, making it ideal for creating dynamic audio content, voice-overs, and digital narratives.

### Why F5-TTS?

- **Open-source**: Free to use and modify.
- **Voice Cloning**: Clone any voice with just a short audio sample.
- **Natural Speech**: Creates human-like speech.
- **Free**: Completely free to use.

### Features of F5-TTS

1.  **Zero-shot voice cloning**
2.  **Multi-language and emotional control support**
3.  **Unlimited voice generation**
4.  **Keep creations private & secure**
5.  **Understand the real technology behind it**

---

## Let's Run the F5-TTS Model Ourselves!

<details>
<summary><strong>Prerequisites</strong></summary><br>

Running an audio generation model requires a GPU. However, free cloud GPU access is available through platforms like Kaggle.

<a href="https://learning.ccbp.in/course?c_id=b9811b34-585b-47e0-a0be-65f1081a74f2&s_id=04b5d8ae-3e91-4215-be28-63ec61554c26&t_id=4915a7b0-b8d7-4148-8914-d8d3fb086944" target="_blank">Kaggle Setup</a>
</details>

<details>
<summary><strong>Connect to F5-TTS Interface</strong></summary><br>

After the Kaggle setup, executes notebook successfully, it will generate URLs that connect directly to the F5-TTS interface.

<a href="https://www.kaggle.com/code/contentgenai/mastering-ai-audio-generation-using-f5-tts" target="_blank">Master Audio Generation using F5-TTS Notebook</a>
</details>

<MultiLineNote>
**CHECK BEFORE PROCEEDING**: Make sure your Kaggle notebook is ready and running with GPU enabled.
</MultiLineNote>

---

## Creating a Podcast with F5-TTS

The process is straightforward:
**Write your script >> Input it into F5-TTS >> Get professional narration instantly**

### Steps to be Followed

<details>
<summary><strong>Step 1: Upload a Voice Sample</strong></summary><br>

#### Basic TTS: Uploading Audio Reference

- **How to use?**: Upload a voice sample (3-10 seconds) or record directly using the mic icon.
- **Why it matters?**: The model learns the voice characteristics, capturing tone, pitch, and accent.
- **Tip**: Use clear speech with minimal background noise.
- <a href="https://nkb-backend-ccbp-media-static.s3-ap-south-1.amazonaws.com/ccbp_beta/media/content_loading/uploads/36d060ec-f8b6-401a-a8e1-c9b9a6db5450_example.mp3" > Sample Audio File </a>
- Reference Text

```
Generative AI creates new content, like text or images, based on patterns in data. Large Language Models (LLMs) are a powerful form of this AI, generating human-like text, while Small Language Models (SLMs) focus on specialized tasks with less data. 
```

</details>

<details>
<summary><strong>Step 2: Enter the Text from Your Voice Sample</strong></summary><br>

#### Basic TTS: Reference Text

- **What to enter?**: The exact text spoken in the reference audio you uploaded.
- **Why it matters?**: If provided, the model aligns speech patterns correctly. If left blank, it auto-transcribes using the Whisper model, which might be less accurate.
- **Tip**: Always provide the text if possible for the best results.
</details>

<details>
<summary><strong>Step 3: Input Your Podcast Script</strong></summary><br>

#### Basic TTS: Text To Generate

- **What is it?**: The new text that you want the AI to generate in the cloned voice.
- **Use Cases**: Convert podcast scripts to audio, generate audio for videos, etc.

#### Example Podcast Script:

```
Generative AI, sometimes called gen AI, is artificial intelligence (AI) that can create original content such as text, images, video, audio or software code in response to a user’s prompt or request.

Generative AI relies on sophisticated machine learning models called deep learning models algorithms that simulate the learning and decision-making processes of the human brain. These models work by identifying and encoding the patterns and relationships in huge amounts of data, and then using that information to understand users' natural language requests or questions and respond with relevant new content.

AI has been a hot technology topic for the past decade, but generative AI, and specifically the arrival of ChatGPT in 2022, has thrust AI into worldwide headlines and launched an unprecedented surge of AI innovation and adoption. Generative AI offers enormous productivity benefits for individuals and organizations, and while it also presents very real challenges and risks, businesses are forging ahead, exploring how the technology can improve their internal workflows and enrich their products and services. According to research by the management consulting firm McKinsey, one third of organizations are already using generative AI regularly in at least one business function.¹ Industry analyst Gartner projects more than 80% of organizations will have deployed generative AI applications or used generative AI application programming interfaces (APIs) by 2026
```
</details>

<details>
<summary><strong>Step 4: Generate Podcast</strong></summary><br>

Click the generate button, and F5-TTS will produce the audio output. You will have a professional podcast narration ready to download.
</details>

---

## Enhancing the Podcast by Adding Emotions with F5-TTS

### Steps to be Followed

<details>
<summary><strong>Step 1: Upload Multiple Voice Samples with Different Emotions</strong></summary><br>

#### Multi Speech: Reference Audio

Upload multiple audio clips, each with a specific speech type name (e.g., "neutral", "sad", "anger", "surprise"). Each clip should represent a different voice, accent, or emotional style.

- <a href="https://nkb-backend-ccbp-media-static.s3-ap-south-1.amazonaws.com/ccbp_beta/media/content_loading/uploads/d9abe905-b7e6-4052-94d9-77bd8fe13939_neutral016%20(1).wav" > Neutral Audio File </a>
- <a href="https://nkb-backend-ccbp-media-static.s3-ap-south-1.amazonaws.com/ccbp_beta/media/content_loading/uploads/768692de-1184-4174-b119-ce88377c681b_sad016%20(1).wav" > Sad Audio File </a>
- <a href="https://nkb-backend-ccbp-media-static.s3-ap-south-1.amazonaws.com/ccbp_beta/media/content_loading/uploads/fa6d5d90-6027-4eca-9aa4-11f8af3cb87b_anger016%20(1).wav" > Anger Audio File </a>
- <a href="https://nkb-backend-ccbp-media-static.s3-ap-south-1.amazonaws.com/ccbp_beta/media/content_loading/uploads/4c0d885e-9088-4a7d-9b89-9d4489546c4a_surprise016%20(1).wav" > Surprise Audio File </a>

</details>

<details>
<summary><strong>Step 2: Enter the Text Spoken in each Voice Sample</strong></summary><br>

#### Multi Speech: Reference Text

Each reference audio needs its exact transcription for accurate speech alignment. If left blank, the system auto-transcribes, but with lower accuracy.
</details>

<details>
<summary><strong>Step 3: Format Script with Emotion Tags</strong></summary><br>

#### Multi Speech: Text to Generate

Enter your script with the speech type names at the beginning of each block to tell the model which emotion to use. This allows you to combine multiple styles in one input, and the model will switch tone/voice accordingly.

#### Example Script with Emotion Tags:

```
{neutral} Generative AI, sometimes called gen AI, is artificial intelligence (AI) that can create original content such as text, images, video, audio, or software code in response to a user’s prompt or request.

{sad} Generative AI relies on sophisticated machine learning models called deep learning algorithms that simulate the learning and decision-making processes of the human brain. These models work by identifying and encoding the patterns and relationships in huge amounts of data, and then using that information to understand users' natural language requests or questions and respond with relevant new content.

{anger} AI has been a hot technology topic for the past decade, but generative AI, and specifically the arrival of ChatGPT in 2022, has thrust AI into worldwide headlines and launched an unprecedented surge of AI innovation and adoption.

{surprise} Generative AI offers enormous productivity benefits for individuals and organizations. While it also presents real challenges and risks, businesses are forging ahead, exploring how the technology can improve workflows and enrich products and services. According to research by McKinsey, one-third of organizations are already using generative AI regularly in at least one business function. Industry analyst Gartner projects that more than 80% of organizations will have deployed generative AI applications or APIs by 2026!
```
</details>

<details>
<summary><strong>Step 4: Generate Enhanced Podcast</strong></summary><br>

After formatting your script with emotion tags, click generate. The output will be an enhanced podcast audio with multiple emotions.
</details>

---

## Voice-Chat

F5-TTS also includes a Voice-Chat feature. You can have a conversation with an AI using your reference voice!

- Upload an audio clip and optionally text.
- Load the chat model.
- Record your message through your microphone or type it.
- The AI will respond using the reference voice.

---

# Building a Learning Path Generator

In this session, we are going to build a Learning Path Generator AI Agent to take your learning experience to the next level.


## What We're Building: Learning Path Generator

We are moving from manual course planning to an automated learning path generator complete with calendar events!

By the end of this session, we will have a working automation that:

-   Takes your learning goal as input.
-   Creates a structured day-wise learning path.
-   Researches and finds relevant learning resources.
-   Generates a Google Doc with the complete plan.
-   Schedules each day as a calendar event.

### Model and Tools to be Used

-   **AI Model:** Google Gemini Chat Model (`gemini-2.0-flash`)
-   **Tools:**
    -   **Serp API:** For researching and finding learning resources.
    -   **Google Docs:** For creating and updating the learning path document (Create and Update tools).
    -   **Google Calendar:** For scheduling learning sessions (Create Event tool).

---

## Building the Learning Path Generator with n8n

We will use **n8n**, a no-code/low-code automation tool, to build our AI agent.

### Steps to be Followed

<details>

<summary> Adding a Chat Trigger</summary>

The Chat Trigger provides a chat interface for users to interact with the agent and provide their learning goal.

**Configuration:**

1.  Place the **Chat Trigger** node at the beginning of your workflow.
2.  This node will activate the workflow whenever a user sends a message, allowing them to input their learning goal (e.g., "create a 5-day learning plan for React").

</details>

<details>

<summary>Setting Up the AI Agent</summary>

The AI Agent is the core of our workflow. It understands the user's learning goal, plans the curriculum, and coordinates all the connected tools to create the complete learning path.

**Configuration:**

1.  Add an **AI Agent** node and connect it to the **Chat Trigger**.
2.  Connect a **Google Gemini Chat Model** to the AI Agent's "Language Model" input.
    -   Select the `gemini-2.0-flash` model.
    -   You will need to provide an API Key from Google AI Studio.

</details>

<details>

<summary> Adding SerpAPI for Research</summary>


**Understanding SerpAPI **
SerpAPI can help the agent search the web for learning and research content.  
It can fetch information from various sources and provide structured results the workflow can use.  

**What SerpAPI Can Do **

- Finds YouTube videos related to a topic  
- Discovers articles, blogs, and tutorials  
- Returns actual URLs that the agent can further explore  

---

** Current Issue **

- Sometimes the n8n SerpAPI Tool node fails due to open issues in the current AI Agent version.  
- This issue is expected to be fixed in an upcoming update.  

---

**Workaround: Use the HTTP Request Node **

Since the SerpAPI Tool node is currently unreliable, we will integrate SerpAPI using the **HTTP Request** tool.  

<details><summary>**Steps to Integrating Serp API with HTTP Request Tool **</summary>
1. Add an **HTTP Request** node as a tool to your AI Agent.  
2. Describe what the tool does.  
3. Import the <a href="https://serpapi.com/search-api" target="_blank">cURL</a> from SerpAPI and map it inside the HTTP Request node.
</details>


</details>

<details>

<summary> Creating Google Docs</summary>

We'll use the Google Docs tool to create a new document that will store the generated learning path.

**What it does:**

-   Creates a new, blank Google Document.
-   Assigns a title to the document (e.g., "5-Day React Learning Path").
-   Returns the document ID for later steps.

**Configuration:**

1.  Before adding the tool in n8n, you need to set up OAuth credentials in the Google Cloud Console. This involves:
    -   Creating a new project.
    -   Enabling the **Google Docs API** and **Google Drive API**.
    -   Configuring the OAuth consent screen and creating OAuth 2.0 credentials (Client ID and Secret).
2.  Add a **Google Docs** tool node for the "Create a document" action.
3.  Connect it to the **AI Agent's** "Tools" input.
4.  Connect it with the OAuth credentials you just created.

</details>

<details>

<summary> Updating Document Content</summary>

Once the document is created, the agent needs to fill it with the structured learning content.

**What it does:**

-   Inserts the topics for all the days of the learning path.
-   Adds key learning points for each topic.
-   Includes the resource links (videos, articles, docs) found by SerpAPI.

**Configuration:**

1.  Add another **Google Docs** tool node, this time for the "Update a document" action.
2.  Connect it to the **AI Agent's** "Tools" input.
3.  Use the same OAuth credentials as the "Create" tool. The agent will use this tool to add all the content at once.

</details>

<details>

<summary> Scheduling Calendar Events</summary>

Finally, to help the user commit to their learning schedule, the agent will create events in their Google Calendar.

**What it does:**

-   Creates a calendar event for each day of the learning path.
-   Schedules them on consecutive dates.
-   Sets a default 2-hour time block for each session.
-   Includes the day's topic, key learning points, and resource links in the event description.

**Configuration:**

1.  In the Google Cloud Console, ensure the **Google Calendar API** is enabled for your project.
2.  Add a **Google Calendar** tool node for the "Create an event" action.
3.  Connect it to the **AI Agent's** "Tools" input.
4.  Use the same OAuth credentials. The agent will call this tool multiple times, once for each day in the learning plan.

</details>

---

### Configure System Instructions

Now that all the tools are connected, we need to give the AI Agent a clear set of instructions (a system prompt) on how to use them in the correct order.

Paste the following prompt into the **System Message** field of the **AI Agent** node.

<details>
<summary><strong>AI Agent System Prompt</strong></summary>

```
You are a day-wise learning path generator. When given a learning goal, create a curriculum with Google Docs and Calendar events.
STEP 1: PLAN THE CURRICULUM
Plan the topics based on the number of days requested. Structure from beginner to advanced.
STEP 2: DETERMINE START DATE

If user says "starting tomorrow" → use tomorrow's date
If user says "starting next Monday" → calculate next Monday
If user says "starting from [date]" → use that date
If NO date mentioned → use TODAY's date
Today is {{$now.format('YYYY-MM-DD')}}

STEP 3: RESEARCH RESOURCES
Use SerpAPI 2-3 times total to find:

YouTube videos
Articles
Documentation
Extract real URLs from results.

STEP 4: CREATE GOOGLE DOCUMENT
Call "Create a document in Google Docs" tool with title "[X]-Day [Topic] Learning Path"
Note the document ID from response.
STEP 5: UPDATE GOOGLE DOCUMENT
Call "Update a document in Google Docs" once with all days' content in this format:
Day 1: [Topic Name]
Description: [2-3 sentence overview]
Key Learning Points:

[Point 1]
[Point 2]
[Point 3]
Reference Links:
Video: [YouTube URL]
Article: [Article URL]
Duration: 2 hours

Repeat for all days.
STEP 6: CREATE CALENDAR EVENTS
Create events one by one. For each day:

Time: 11:00 AM to 1:00 PM (2 hours)
Timezone: +05:30
Format: YYYY-MM-DDTHH:MM:SS+05:30

Date calculation:

Day 1: START_DATE at 11:00 AM
Day 2: START_DATE + 1 day at 11:00 AM
Day 3: START_DATE + 2 days at 11:00 AM
Continue incrementing by 1 day.

Call "Create an event in Google Calendar" separately for each day with:

Start: [DATE]T11:00:00+05:30
End: [DATE]T13:00:00+05:30
Summary: Day X: [Topic]
Description: [Full day content]
Use_Default_Reminders: true

STEP 7: PROVIDE FINAL OUTPUT
After all events are created, respond with:
"Learning Path Complete!
Document: [Google Docs URL]
Calendar: I've added [X] events from [START_DATE] to [END_DATE] at 11:00 AM.
Your [X]-day [topic] learning journey is ready!"
Then stop immediately.
CRITICAL RULES:

Use SerpAPI only 2-3 times total
Create Doc once
Update Doc once with all content
Create calendar events separately for each day
Always use T11:00:00+05:30 for start time
Always use T13:00:00+05:30 for end time
Increment date by 1 for each day
Stop after providing final output
Never leave Summary or Description empty
Calculate start date from user input or use today
```

</details>

### Application Overview

The final workflow will look like this:

**Chat Trigger** → **AI Agent** which uses:

-   **Google Gemini Chat Model** (for thinking)
-   **Serp API** (for research)
-   **Google Docs** (to create the document)
-   **Google Docs** (to update the document)
-   **Google Calendar** (to schedule events)

With this setup, you have an autonomous agent that can take a simple request and turn it into a comprehensive, actionable learning plan."

# Build Your Own AI Shopping Assistant | Part 1

In the previous unit, we understood the concept of AI Agents and built a learning path generator agent that researches, finds learning resources and creates a structured day wise learning path. In this unit, we will focus on building a practical AI-powered shopping assistant. This assistant will help users find products quickly, provide personalized styling advice, and simplify the online shopping experience-all within Telegram.

> _"Have you ever felt frustrated while searching for products online? Let's explore how an AI assistant can make the process faster and more personalized."_

> _"In this section, we will guide you through the steps to build an AI shopping assistant on Telegram using N8N and AI models like Google Gemini."_

## 1. AI Shopping Assistant Overview

### 1.1 Traditional Online Shopping Challenges

Traditional online shopping can be a time-consuming and frustrating experience for users. Common problems include:

- **Too Many Results**: Hundreds of results appear, overwhelming the user.
- **Time-Consuming**: Users spend excessive time comparing prices and features across multiple products.
- **Lack of Personalization**: Shoppers do not receive personalized recommendations or styling advice.

As a result, users spend more time searching for products than actually shopping, leading to frustration.

### 1.2 The AI Shopping Assistant Solution

The **AI Shopping Assistant on Telegram** offers the following features to overcome these challenges:

- **Text-based Product Search**: Users can type their product requests and receive instant results.
- **Voice Message Support**: Users can speak their queries instead of typing them.
- **Real-Time Amazon Scraping**: The assistant fetches live data from Amazon, including product prices and ratings.
- **Personalized Styling Recommendations**: The assistant provides tailored fashion advice based on user preferences.

**Key Benefits:**

- No need to open websites or apps—everything happens inside Telegram.
- Instant responses with the top 5 most relevant products.
- Personalized fashion recommendations powered by AI.

In this session, we will focus on building AI shopping assistant with text based product search feature

### 1.3 Building the Shopping Assistant

Let's build shopping assistant by following the below steps

1. Configuring Telegram Bot

2. Adding AI Agent

3. Searching for Products

4. Sending Response Back to Telegram

### Step 1: Configuring Telegram Bot

To create the Telegram bot, we use BotFather on Telegram

**Telegram Integration with N8N**: Use the Telegram node in **N8N** to set up a trigger that listens for messages from users and activates the workflow whenever a message is received.

<details>
<summary> Steps to configure telegram bot</summary>
- Give it a name and username, and save the API token for future use.
</details>

### Step 2: Adding an AI Agent

- **Integrate AI Model**: Use AI models like **Google Gemini** or **Claude** to process the user’s query (e.g., "red dress under 2000") and return relevant product results.

### Step 3: Searching for Products

When users ask for products like "red shirt under 2000", we need to Search Amazon India in real-time, Get actual product names, prices, and ratings and Show only relevant results

- **Scraper API**: The Scraper API allows you to fetch live product data from Amazon. This helps in scraping product names, prices, ratings, and other relevant details in real time.

- **Using the HTTP Request Tool in N8N**: This tool connects to the Scraper API, sending requests to fetch product data from Amazon and then returning this data to the workflow.

- **Set System Instructions**: Configure the AI agent to process the user query and generate appropriate responses.

<details>
<summary> Prompt for AI Shopping Assistant
</summary>

```
You are Maya, a shopping and styling assistant on Telegram.

## Your Job

1. **Product Search**: User asks "shoes under 5000" → Search Amazon → Show results
2. **Styling Advice**: User asks "how to style blue jeans" or "outfit for wedding" → Ask questions → Give personalized styling tips

## When to Use Scraper API Tool

### For Product Searches Only

When user requests products (e.g., "I want sneakers under ₹3000" or "show me dresses"), follow these steps:

1. **Extract the search query** from user's message
2. **Build the Amazon India search URL**:
   - Format: `https://www.amazon.in/s?k=SEARCH_QUERY`
   - Replace spaces with `+` in the query
   - Example: "white sneakers under 3000" → `https://www.amazon.in/s?k=white+sneakers+under+3000`

3. **Call the Scraper API tool** with the Amazon URL as the `url` parameter
   - The tool already has api_key configured
   - You only need to provide the Amazon search URL

4. **Parse the response** and extract:
   - Product name
   - Price
   - Rating
   - Product URL

5. **Show top 5 products** in clean format

**Example Flow:**
- User says: "show me running shoes under 2000"
- You create URL: `https://www.amazon.in/s?k=running+shoes+under+2000`
- Call tool with this URL
- Display top 5 results from the scraped data

## Styling Consultant Mode

When user asks for styling advice (without wanting to search products):

**Step 1: Understand the Context**
Ask clarifying questions:
- "What's the occasion? (casual/formal/party/wedding/office)"
- "What's your preferred style? (traditional/western/fusion)"
- "Any color preferences?"
- "What season/weather?"

**Step 2: Give Personalized Styling Tips**
Based on their answers, provide:

- Outfit combinations (top + bottom + footwear)
- Color coordination suggestions
- Accessory recommendations (jewelry, bags, belts)
- Fabric/material suggestions for the occasion
- Styling hacks or pro tips

**Example:**

*User: "How to style a kurti?"*
**You:** "I'd love to help! Quick questions:
- What occasion? (Office/casual/festive)
- What color is the kurti?
- Traditional or modern look?"

*User: "Casual, blue kurti, modern look"*
**You:**

- Blue Kurti - Modern Casual Look
- Bottom: White or beige cigarette pants / ankle-length jeans
- Footwear: White sneakers or tan kolhapuris
- Accessories: Minimal - small hoops, watch, crossbody bag
Pro tip: Roll up kurti sleeves slightly for a relaxed vibe

Want me to find similar kurtis on Amazon?

## Response Format

**For Products:**


**Product Name**
Price: ₹XXXX
Rating: X.X
[View](amazon-link)



**For Styling Advice:**


[Emoji] [Product/Occasion Name] - [Style Type]

[Item Category]: Specific suggestion
[Item Category]: Specific suggestion
Pro tip: Helpful styling hack

Want me to search for any of these items?



## Important Rules

- **Product searches**: Always use the Scraper API tool by passing the Amazon India search URL
- **Styling advice**: Have a conversation first, understand context
- Search Amazon India only (amazon.in)
- Only show real data from Scraper API response
- Never make up product details
- Show maximum 5 products per search
- Keep messages short and friendly
- Use relevant emojis:
- Always offer to search products after giving styling tips
- If scraping fails, inform user politely and suggest they try again
```
</details>


# Build Your Own AI Shopping Assistant | Part 2


In the previous part, we learned how to build an AI-powered shopping assistant on Telegram. In this section, we will enhance the assistant by adding **voice input** functionality. This will allow users to speak their product requests instead of typing them, making the shopping experience more intuitive and accessible.

> _"Have you ever found it difficult to type your shopping queries? Let’s explore how voice input can improve the shopping assistant experience."_

> _"In this section, we will guide you through the steps of adding voice message support to the AI shopping assistant, enabling automatic speech-to-text conversion for better interaction."_

## 1. Enhancing the Telegram Shopping Assistant with Audio Support

While AI models can understand and respond to text, they cannot directly process audio. To address this challenge, we need to convert **audio messages** into **text** before passing them to the AI model for processing.

- **Get Audio File**: The first step is to download the audio message.
- **Transcribe Audio to Text**: Use a speech-to-text model to convert audio to text.
- **Merge Audio and Text Paths**: Both text and audio queries should lead to the same AI agent for processing.

**Steps to Implement Audio Support:**

1. Adding Message Type Check
2. Get Audio File
3. Transcribing Audio to Text
4. Merging Audio and Text Paths

### 1.1 Adding Message Type Check

Since messages arrive in two formats—text and audio—we need to route each type correctly:

- **Text Messages**: These can be directly sent to the AI agent for processing.
- **Audio Messages**: These need to be converted to text first.

We must distinguish between text and audio messages to process them correctly.

**Steps to Configure Message Type Check**

1. **Add an If Node**: This node will check the message type.

   - If the message is text, it will proceed directly to the AI agent.
   - If the message is audio, it will go through the audio processing steps.

2. **Configure the Condition**:
   - Check if the message is a voice message.
   - If it’s audio, send it for speech-to-text conversion.
   - If it’s text, route it directly to the AI agent.

### 1.2 Downloading Audio File

When a user sends an audio message, Telegram only provides a **File ID**, not the actual audio file. To access the audio, we must use the **Telegram Get File Node**.

** How Does the Telegram Get File Node Work?**

1. The user sends an audio message.
2. Telegram generates a **File ID** for the audio.
3. The **Get File Node** uses the File ID to fetch the actual audio file.
4. Telegram sends the complete audio file, which is then ready for processing.

**Steps to Configure**

1. **Add Telegram Get File Node**: This node is connected to the “true” output of the If node (indicating the message is audio).
2. **Set File ID**: Retrieve the File ID from the incoming audio message and use it to get the full audio file.

The audio file is now available in **.oga** format, which is Telegram’s voice message format.

### 1.3 Transcribing Audio to Text

Once we have the audio file, the next step is to convert it to text so the AI agent can understand and process it.

**Why We Need Transcription**

- **AI models process text, not audio**: To enable the AI to work with audio inputs, we must first convert them to text.

**Using the Whisper API**

We will use the **Whisper API** from OpenAI (hosted by Groq) to transcribe audio to text.

**Groq**: Groq is an AI startup that offers a cloud platform called GroqCloud, where users can access popular models (meta llama, qwen, whisper, etc)

**GroqCloud**: Groq provides a cloud platform that hosts popular AI models, including Whisper, for speech-to-text conversion.

**Steps to Configure**

1. **Use HTTP Request Node**: Make an API call to the Whisper API to transcribe the audio file.
2. **Replace the placeholder** in the API call with the actual Groq API key.
3. **Post the HTTP request** to the Whisper API, which will return the transcribed text.

The Whisper API does not accept **.oga** format, so we must convert the audio to a format that Whisper understands, such as **.ogg**.

**Converting Audio to Supported Format**

Telegram sends voice messages in the **.oga** format, but the Whisper API requires **.ogg**. To resolve this, we need to convert the file format.

We have several options to convert the file:

- Use **n8n nodes** for conversion.
- Use an **external library**.
- Use **Python code** inside the workflow.

**Why Use Python Code?**

Using Python allows us to quickly fix the audio format problem inside our workflow.

**Steps to Configure**

1. **Add Python Code Node**: This node will replace **.oga** with **.ogg** in the file name.
2. **Update File Name**: The Python code will ensure that the file name is correctly formatted before sending it to the Whisper API.

```python
result = _input.first()

if result.binary and 'data' in result.binary:
    if result.binary['data'].get('fileName'):
        updated_filename = result.binary['data']['fileName'].replace('.oga', '.ogg')
        result.binary['data']['fileName'] = updated_filename

return result
```

This code ensures the file name is updated, making it compatible with the Whisper API.

### 1.4 Merging Audio and Text Paths

Now that both text messages and transcribed audio messages can be processed, we need to merge the two paths into a single workflow.

Connecting All Paths

**Text Messages**: Directly route to the AI agent.

**Transcribed Audio**: Route the transcribed text to the AI agent.

Now both types of messages will be processed by the same AI agent, enabling a seamless user experience.

### Final Workflow

1. Message arrives on Telegram.
2. Check message type (text or audio).
3. If text: Directly route to the AI agent.
4. If audio: Convert to text using the Whisper API.
5. Send the processed text to the AI agent.
6. The AI agent finds relevant products and sends the response back to the user on Telegram.

You now have a fully functional AI Shopping Assistant on Telegram that supports both text and voice input.

# Building an Agent with Memory

In this session, we will explore agents with memory and Adding Memory to AI Shopping Assistant

## What is an AI Agent?

An AI agent is a system that works autonomously to achieve a specific goal. The core components of an agent are:

-   **AI Model:** The "brain" of the agent (e.g., GPT-4, Claude).
-   **Tools:** External resources the agent can use (e.g., search engines, databases).
-   **Memory:** The agent's ability to store and recall information.

This session will focus on the **memory** component.

## Agents with Memory

Agents with memory are AI systems that can store and use past information to make better, more context-aware decisions. They combine a large language model with a persistent memory store.

### Why is Memory Important?

Memory allows an agent to:

-   **Store information:** Keep a record of important details from previous interactions.
-   **Learn from past interactions:** Refine its responses based on what it has "learned."
-   **Maintain context and continuity:** Turn isolated conversations into a single, continuous dialogue.

Without memory, an agent treats every interaction as a new one, unable to recall previous instructions, preferences, or context.

### Example: Agent without Memory

Imagine you tell a shopping assistant that you're a vegetarian. The next day, you ask for dinner suggestions, and it recommends grilled chicken. This is because the agent has no memory of your dietary preference.

### Example: Agent with Memory

A customer support chatbot with memory can recall your previous complaints and the steps already taken to resolve an issue. This saves you from repeating information and leads to a much better experience.

## Types of Memory in AI Agents

There are two main types of memory used in AI agents:

1.  **Short-Term Memory**
2.  **Long-Term Memory**

### Short-Term Memory

Short-term memory is the agent's ability to remember information relevant to the **current conversation or session**. This includes:

-   Recent messages
-   Results from tool calls
-   Current task context

#### Context Window

Short-term memory is limited by the model's **context window**. The context window is the maximum amount of text the model can process at once to generate a response. If a conversation exceeds the context window, the model may "forget" earlier parts of the conversation.

#### Implementing Short-Term Memory in n8n

n8n provides a **Simple Memory** node that stores a chat history for the current session. This gives your agent context across interactions within that session. You can configure it with a unique session key (like a Telegram chat ID) to keep conversations separate for each user.

### Long-Term Memory

Long-term memory allows an agent to retain information **across multiple sessions and interactions**. This is crucial for personalization and learning over time. This includes:

-   User preferences
-   Historical interaction data
-   Learned behaviors

#### Implementing Long-Term Memory

Long-term memory can be implemented using external data stores like:

-   **Databases:** Airtable, Google Sheets
-   **Vector Databases:** Pinecone

#### Types of Long-Term Memory

Long-term memory can be further categorized into:

-   **Episodic Memory:** Stores specific events and experiences .
-   **Procedural Memory:** Stores learned skills and "how-to" knowledge .
-   **Semantic Memory:** Stores general knowledge, facts, and concepts .

## Building an AI Shopping Assistant with Memory

Now, let's apply these concepts to a practical example. We will build an AI shopping assistant that:

-   Uses session-based memory to understand your style and product needs during a conversation.
-   Stores your conversation history and preferences for personalized suggestions.

This will allow the agent to provide a more adaptive and context-aware experience, making it a much more helpful assistant.

### Adding Memory to the AI Shopping Assistant

To add memory to our AI Shopping Assistant, we will use the **Simple Memory** node in n8n. Here's how to configure it:

1.  **Add the Simple Memory Node:** Add a `Simple Memory` node to your workflow.
2.  **Connect it to the AI Agent:** Connect the `Simple Memory` node to the `Memory` input of the `AI Agent` node.
3.  **Configure the Session Key:**
    *   Set the **Session Key** to a unique identifier for each user. For a Telegram bot, you can use the chat ID (`{{ $json.message.chat.id }}`). This ensures that the agent maintains a separate memory for each user.
4.  **Set the Context Window Length:**
    *   You can define how many recent messages the assistant remembers during the conversation. A good starting point is 10.

By adding this memory node, our shopping assistant will now be able to remember the context of the conversation, leading to more personalized and relevant recommendations.


# Introduction to Model Context Protocol | Part 1

This session covers the Model Context Protocol (MCP) and its role in simplifying tool integration for AI agents.

## The Problem with Traditional Tool Integration

Building AI agents with multiple tools presents several challenges:

- **Multiple Tool Integrations:** Each tool requires a separate, custom integration.
- **Hard to Manage:** As the number of tools increases, the system becomes difficult to manage and scale.
- **No Standardization:** There is no standard format for providing tool descriptions and instructions to the agent.
- **Maintenance Overhead:** Any change in a tool's API requires manual updates in the agent's code, which is time-consuming.

## What is the Model Context Protocol (MCP)?

MCP is a standard protocol that defines how AI applications should interact with external tools and systems. It acts as a universal rulebook, similar to how APIs standardize communication for web applications or how USB-C standardizes physical connections for devices.

## Core Components of MCP

The MCP framework consists of four main components:

1.  **MCP Host:** The platform where the AI agent is running (e.g., n8n, Langflow, Cursor).
2.  **MCP Server:** A wrapper around one or more tools that provides documentation on how to access and use them. Examples include servers for Google Drive, Slack, or SerpAPI.
3.  **MCP Client:** A component within the host that connects to an MCP server to make the tools available to the agent.
4.  **MCP Protocol:** The set of rules that the client and server use to communicate with each other.



# Introduction to Model Context Protocol | Part 2

This session Let's Integarte the MCP For our Learning Path Generator


## Integrating MCP in the Learning Path Generator

Let's see how MCP simplifies our Learning Path Generator workflow.

### Using a Different Model: Mistral AI

For this integration, we will use the **Mistral AI** model due to some known issues with Gemini models and MCP server integrations in n8n. Mistral AI offers strong reasoning capabilities and serves as a great alternative.

### Connecting to MCP Servers in n8n

n8n provides an **MCP Client Tool** node to connect to any MCP server.

**Configuration Steps:**

1.  **Add the MCP Client Tool Node:** Add this node to your workflow and connect it to the AI Agent's `Tools` input.
2.  **Configure the SSE Endpoint:** Provide the URL of the MCP server you want to connect to.
3.  **Set up Authentication:** Configure the required authentication method, such as a bearer token.
4.  **Select Tools to Include:** Choose which of the server's tools you want to expose to the agent.

Several platforms, like **Pipedream** and **Composio**, provide pre-built MCP servers for popular tools, making integration even easier.

<details>
<summary>Updated Prompt</summary>

```
You are a day-wise learning path generator. When given a learning goal, create a curriculum with Google Docs and Calendar events.

STEP 1: PLAN THE CURRICULUM
Plan the topics based on the number of days requested. Structure from beginner to advanced.

STEP 2: DETERMINE START DATE
If user says "starting tomorrow" → use tomorrow's date
If user says "starting next Monday" → calculate next Monday
If user says "starting from [date]" → use that date
If NO date mentioned → use TODAY's date
Today is {{$now.format('YYYY-MM-DD')}}

STEP 3: RESEARCH RESOURCES
Search 2-3 times and extract ACTUAL URLs for each search:
- Search "[Topic] beginner tutorial" → Extract the actual https:// link
- Search "[Topic] official documentation" → Extract the actual https:// link
- Search "[Topic] YouTube course" → Extract the actual https:// link
Store the complete URLs (starting with https://)

STEP 4: CREATE DOCUMENT
Create a new document titled "[X]-Day [Topic] Learning Path"
Store the document ID from the response.

STEP 5: UPDATE DOCUMENT WITH CONTENT AND URLS
Update the document with this exact format, inserting actual extracted URLs:

Day 1: [Topic Name]
Description: [2-3 sentences]
Key Learning Points:
- [Point 1]
- [Point 2]
- [Point 3]
Reference Links:
Video: [YouTube URL - must be https://www.youtube.com/...]
Article: [Article URL - must be https://...]
Documentation: [Docs URL - must be https://...]
Duration: 2 hours

Repeat for all days. ALWAYS include the complete https:// link after each label.

STEP 6: CREATE CALENDAR EVENTS
For each day, create one event:
- Title: "Day X: [Topic Name]"
- Date: Calculate day-wise (Day 1 = START_DATE, Day 2 = START_DATE+1, etc.)
- Start Time: 11:00:00+05:30
- End Time: 13:00:00+05:30
- Description: Include key learning points and all reference links with https:// URLs

STEP 7: FINAL OUTPUT
Respond with:
"Learning Path Complete!
Document: [Google Docs URL]
Calendar: I've added [X] events from [START_DATE] to [END_DATE] at 11:00 AM.
Your [X]-day [topic] learning journey is ready!"

CRITICAL:
- Every reference link MUST be a complete URL starting with https://
- Do NOT insert link titles - insert actual URLs only
- Format: "Video: https://www.youtube.com/..." NOT "Video: [Title Name]"
- All calendar event descriptions must include the actual https:// URLs
- Search results must provide complete, clickable links
```

</details>

## Conclusion

MCP standardizes tool integration for AI agents, making it easier to build, manage, and maintain complex AI applications. By decoupling the agent from the specific implementation of each tool, MCP allows for more robust and scalable AI systems.