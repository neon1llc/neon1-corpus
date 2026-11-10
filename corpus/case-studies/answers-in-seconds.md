---
id: case-answers-in-seconds
title: "Answers in seconds, with sources"
summary: "Staff spent minutes hunting through Microsoft 365, or interrupted a senior colleague."
type: case-study
status: adopted
client: accounting firm
area: "cloud & AI"
updated: 2026-11-10
created: 2026-11-06
edition: "1.1"
consumers: [site, chat, knowledge, ai]
pdf: true
key: accounting
order: 1
stat_key: "~5 min → 14 s"
stat: "lookup · recall 72% → 94%"
short_needs: "Staff spent minutes hunting through Microsoft 365, or interrupted a senior colleague."
short_execute: "An assistant on AWS Bedrock, designed to answer from approved documents each person may see."
short_observe: "Timed real lookups before and after, and scored 80 test questions for accuracy."
short_normalize: "Next, an MCP server over the same search, so agents get answers with the same permissions."
origin: "neon1-site src/app/public/index.html#case-accounting"
---

# Answers in seconds, with sources

## Needs

The firm's knowledge was spread across Microsoft 365: policies, procedure manuals, Word files, PDFs, and client documents. Staff could usually find an answer, but a routine lookup took 2 to 10 minutes, and often meant asking a senior colleague who knew where things lived. Drafts, old versions, and client-restricted files sat right next to the right answer, so a simple chatbot would have been risky.

The ask was simple: let staff ask normal questions, return the approved answer with its document, and never make the AI more authoritative than the source.

## Execute

This was my first project with an AWS partner, [Xenoss](https://xenoss.io), who helped with design and now with maintenance. I handled ingestion, embeddings, retrieval, and answer quality.

- Only documents in approved Microsoft 365 libraries are synced into versioned, encrypted S3, keeping their source, version, and access details.
- Bedrock Knowledge Bases with Titan embeddings and OpenSearch Serverless run hybrid search, so exact accounting terms and form numbers match as well as differently worded questions.
- By design, each question is checked against what that person is allowed to see before anything is retrieved, and the assistant is built to answer from the retrieved passages, with citations, or to say it doesn't know. How well it kept to that was measured separately, below.
- Built with Terraform and deployed through GitHub Actions, with CloudWatch tracking ingestion, retrieval, and answer time separately.

## Observe

| Measure                                  | Before       | After  |
|------------------------------------------|--------------|--------|
| Median lookup, answer and source checked | ~4.8 min     | 13.6 s |
| Slowest 5% of lookups                    | up to 10 min | ~24 s  |
| Right passage found (recall at 8)        | 72%          | 94%    |
| Answers fully supported by their source  | 78%          | 92%    |
| Interruptions of senior staff per week   | ~18          | ~7     |

Measured on 80 representative questions, including ones the assistant should refuse, and judged by two reviewers. A fast answer from the wrong document counted as a failure.

These results describe that test set, not a guarantee. In the evaluation, 92% of answers were fully supported by their source, so the rest were not. Each answer carries its citations so the source can be checked.

## Normalize

Microsoft 365 stays the source of truth, and the search index can be rebuilt from it at any time. The firm owns which documents are approved and who can see them. Next is an MCP server in front of the same retrieval, so assistants and agents can use the firm's knowledge with the same per-person permissions, followed by narrow, reviewable agent actions where they save real time.
