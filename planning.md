# Project 1 Planning: The Unofficial Guide

> Write this document before you write any pipeline code.
> Your spec and architecture diagram are what you'll use to direct AI tools (Claude, Copilot, etc.) to generate your implementation — the more specific they are, the more useful the generated code will be.
> Update the Retrieval Approach and Chunking Strategy sections if you change your approach during implementation.
> Update this file before starting any stretch features.

---

## Domain

<!-- What domain did you choose? Why is this knowledge valuable and hard to find through official channels? -->

The domain I chose is Unofficial Guide to CS Courses at Cornell. This knowledge is valuable because it provides extra insight and information about CS courses from the perspective of students who have actually take the courses. Official course rosters only give prerequisites and dry descriptions. They don't tell you the actual project workloads, which professors give the best feedback, or how brutal the weekly problem sets are. 

---

## Documents

<!-- List your specific sources: URLs, subreddit names, forum threads, or file descriptions.
     Aim for at least 10 sources that together cover different subtopics or perspectives within your domain. -->

| # | Source | Description | URL or location |
|---|--------|-------------|-----------------|
| 1 | r/Cornell | Comments on the difficulty of CS3110 | https://www.reddit.com/r/Cornell/comments/ag1yav/deleted_by_user/ |
| 2 | r/Cornell | Describes the difficulty of CS2800 and CS3110 | https://www.reddit.com/r/Cornell/comments/1q2brio/how_hard_is_cs_3110_and_cs_2800_actually/ |
| 3 | r/Cornell | Making the correct choice for the probability theory prerequisite for CS4780 | https://www.reddit.com/r/Cornell/comments/vhk16k/cs4780_introduction_to_machine_learning/ |
| 4 | r/Cornell | Listing out and reviewing cs electives | https://www.reddit.com/r/Cornell/comments/10mrbgs/bestmost_useful_cs_electives/ |
| 5 | r/Cornell | Comments answering how useful courses are for the industry and where should a student's focus be in order to maximize their learning | https://www.reddit.com/r/Cornell/comments/gls928/cs_honest_questions/ |
| 6 | GitLab | FAQ from a peer-maintained directory providing general information on all cs courses| https://cornellcswiki.gitlab.io/faq.html |
| 7 | CUReviews | Aggregated student reviews of the CS4780 course | https://www.cureviews.org/course/CS/4780 |
| 8 | General Prereqs | Table showing the general idea of courses that a CS Major should take | data/cs.txt  |
| 9 | Cornell Academic Catalog | Official BS in Computer Science requirements, affiliation GPA cutoffs, and Honors program rules. | https://catalog.cornell.edu/programs/computer-science-bs/ |
| 10 | Engineering Handbook | Official course checklist detailing CS core requirements, credit minimums, and prerequisites. | data/engineering_handbook.txt |

---

## Chunking Strategy

<!-- How will you split documents into chunks?
     State your chunk size (in tokens or characters), overlap size, and explain why those
     numbers fit the structure of your documents.
     A review-heavy corpus warrants different chunking than a long FAQ. -->

**Chunk size:**

**Overlap:**

**Reasoning:**

---

## Retrieval Approach

<!-- Which embedding model are you using (e.g., all-MiniLM-L6-v2 via sentence-transformers)?
     How many chunks will you retrieve per query (top-k)?
     If you were deploying this for real users and cost wasn't a constraint, what tradeoffs
     would you weigh in choosing a different embedding model — context length, multilingual
     support, accuracy on domain-specific text, latency? -->

**Embedding model:**

**Top-k:**

**Production tradeoff reflection:**

---

## Evaluation Plan

<!-- List your 5 test questions with their expected correct answers.
     Questions should be specific enough that you can judge whether the system's response
     is right or wrong. "What are good dining halls?" is too vague.
     "What do students say about wait times at [dining hall name] during lunch?" is testable. -->

| # | Question | Expected answer |
|---|----------|-----------------|
| 1 | | |
| 2 | | |
| 3 | | |
| 4 | | |
| 5 | | |

---

## Anticipated Challenges

<!-- What could go wrong? Name at least two specific risks with reasoning.
     Consider: noisy or inconsistent documents, missing source attribution, off-topic
     retrieval, chunks that split key information across boundaries. -->

1.

2.

---

## Architecture

<!-- Draw a diagram of your pipeline showing the five stages:
     Document Ingestion → Chunking → Embedding + Vector Store → Retrieval → Generation
     Label each stage with the tool or library you're using.
     You can use ASCII art, a Mermaid diagram, or embed a sketch as an image.
     You'll use this diagram as context when prompting AI tools to implement each stage. -->

---

## AI Tool Plan

<!-- For each part of the pipeline below, describe:
     - Which AI tool you plan to use (Claude, Copilot, ChatGPT, etc.)
     - What you'll give it as input (which sections of this planning.md, which requirements)
     - What you expect it to produce
     - How you'll verify the output matches your spec

     "I'll use AI to help me code" is not a plan.
     "I'll give Claude my Chunking Strategy section and ask it to implement chunk_text()
     with my specified chunk size and overlap" is a plan. -->

**Milestone 3 — Ingestion and chunking:**

**Milestone 4 — Embedding and retrieval:**

**Milestone 5 — Generation and interface:**
