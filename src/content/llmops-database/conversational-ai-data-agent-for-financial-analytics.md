---
title: "Conversational AI Data Agent for Financial Analytics"
slug: "conversational-ai-data-agent-for-financial-analytics"
draft: false
webflow:
  siteId: "64a817a2e7e2208272d1ce30"
  itemId: "687e02506b33d5b56c1cd474"
  exportedAt: "2026-02-11T13:30:32.135Z"
  source: "live"
  lastPublished: "2025-12-23T12:21:17.478Z"
  lastUpdated: "2025-12-18T17:15:50.664Z"
  createdOn: "2025-07-21T09:03:12.445Z"
llmopsTags:
  - "data-analysis"
  - "question-answering"
  - "chatbot"
  - "rag"
  - "prompt-engineering"
  - "multi-agent-systems"
  - "agent-based"
  - "human-in-the-loop"
  - "semantic-search"
  - "langchain"
  - "elasticsearch"
  - "fastapi"
  - "postgresql"
  - "monitoring"
  - "api-gateway"
  - "security"
  - "compliance"
  - "guardrails"
  - "reliability"
  - "scalability"
  - "google-gcp"
  - "amazon-aws"
industryTags: "finance"
company: "Uber"
summary: "Uber developed Finch, a conversational AI agent integrated into Slack, to address the inefficiencies of traditional financial data retrieval processes where analysts had to manually navigate multiple platforms, write complex SQL queries, or wait for data science team responses. The solution leverages generative AI, RAG, and self-querying agents to transform natural language queries into structured data retrieval, enabling real-time financial insights while maintaining enterprise-grade security through role-based access controls. The system reportedly reduces query response times from hours or days to seconds, though the text lacks quantified performance metrics or third-party validation of claimed benefits."
link: "https://www.uber.com/en-IN/blog/unlocking-financial-insights-with-finch/"
year: 2025
seo:
  title: "Uber: Conversational AI Data Agent for Financial Analytics - ZenML LLMOps Database"
  description: "Uber developed Finch, a conversational AI agent integrated into Slack, to address the inefficiencies of traditional financial data retrieval processes where analysts had to manually navigate multiple platforms, write complex SQL queries, or wait for data science team responses. The solution leverages generative AI, RAG, and self-querying agents to transform natural language queries into structured data retrieval, enabling real-time financial insights while maintaining enterprise-grade security through role-based access controls. The system reportedly reduces query response times from hours or days to seconds, though the text lacks quantified performance metrics or third-party validation of claimed benefits."
  canonical: "https://www.zenml.io/llmops-database/conversational-ai-data-agent-for-financial-analytics"
  ogTitle: "Uber: Conversational AI Data Agent for Financial Analytics - ZenML LLMOps Database"
  ogDescription: "Uber developed Finch, a conversational AI agent integrated into Slack, to address the inefficiencies of traditional financial data retrieval processes where analysts had to manually navigate multiple platforms, write complex SQL queries, or wait for data science team responses. The solution leverages generative AI, RAG, and self-querying agents to transform natural language queries into structured data retrieval, enabling real-time financial insights while maintaining enterprise-grade security through role-based access controls. The system reportedly reduces query response times from hours or days to seconds, though the text lacks quantified performance metrics or third-party validation of claimed benefits."
---

Uber's Finch represents a comprehensive case study in deploying conversational AI for financial data access, addressing the common enterprise challenge of democratizing data retrieval while maintaining security and accuracy. The system was developed to solve friction in Uber's financial analytics workflow, where analysts previously had to navigate multiple platforms like Presto, IBM Planning Analytics, Oracle Enterprise Performance Management, and Google Docs to access financial data, often requiring complex SQL queries or lengthy data science team requests.

The technical architecture demonstrates several sophisticated LLMOps practices, with Finch built on a modular framework that integrates multiple AI components through Uber's internal Generative AI Gateway. This gateway approach is particularly noteworthy from an LLMOps perspective as it enables model swapping and experimentation without requiring application-level changes, providing operational flexibility as underlying AI technology evolves. The system accesses both self-hosted and third-party large language models through this centralized interface, suggesting a multi-model strategy that's increasingly common in production AI systems.

The orchestration layer uses LangChain's Langgraph for agent coordination, implementing a supervisor agent pattern that routes queries between specialized agents including a SQL Writer Agent and Document Reader Agent. This multi-agent architecture reflects mature LLMOps practices where complex tasks are decomposed into specialized components, each optimized for specific functions. The supervisor agent performs intent routing to determine which sub-agents should handle specific query types, addressing the challenge of handling diverse user intents in conversational AI systems.

A particularly innovative aspect of Finch's implementation is its approach to improving SQL generation accuracy through enhanced metadata management. Rather than relying solely on table schemas and sample rows like traditional LLM-powered SQL agents, Finch maintains an OpenSearch index storing natural language aliases for both SQL table columns and their values. This semantic layer approach addresses a critical challenge in text-to-SQL systems where natural language terms must be accurately mapped to database structures. The system claims this approach "dramatically improves the accuracy of WHERE clause filters," though specific accuracy metrics aren't provided.

The data architecture employs curated domain-specific data marts consisting of single-table datasets that consolidate frequently accessed financial and operational metrics. This design decision reflects careful consideration of LLM limitations in handling complex multi-table joins and database relationships. By pre-structuring data into simplified, single-table formats, the system reduces query complexity and minimizes the potential for LLM-generated SQL errors. The curated approach also enables better governance and access control, with structured permissions ensuring only authorized users can query specific financial dimensions.

From an evaluation and monitoring perspective, Finch implements multi-layered assessment strategies that are essential for production LLM systems. The evaluation framework includes independent assessment of each sub-agent against expected responses, with the SQL Writer Agent specifically evaluated by comparing generated query results to "golden" query results rather than just query syntax. This output-based evaluation approach recognizes that multiple SQL queries can produce the same correct results, focusing on outcome accuracy rather than implementation details.

The system also monitors supervisor agent routing accuracy to identify intent collisions where ambiguous queries might be routed to inappropriate agents. End-to-end validation through simulated real-world queries ensures system-wide reliability, while regression testing re-runs historical queries to detect accuracy drift before deploying system prompt or model changes. This comprehensive evaluation approach demonstrates mature MLOps practices adapted for LLM systems, addressing the unique challenges of monitoring and maintaining conversational AI quality.

Security and access control implementation showcases enterprise-grade LLMOps practices, with role-based access control (RBAC) ensuring that query permissions align with existing organizational data access policies. The system validates user permissions before executing queries and maintains audit trails through integration with Uber's existing authentication systems. This security-first approach is critical for financial AI applications where data sensitivity requires strict access controls.

The user experience design integrates directly with Slack through dedicated APIs, including real-time status updates via callback handlers that inform users about agent operations at each stage of query processing. The system leverages Slack's AI Assistant APIs for enhanced functionality including suggested questions and persistent chat interfaces. This integration strategy reflects thoughtful consideration of user adoption challenges, embedding AI capabilities within existing workflows rather than requiring users to learn new tools.

Performance optimization includes several production-focused strategies such as simultaneous sub-agent execution to reduce response times, SQL query optimization to minimize database load, and pre-fetching of frequently accessed metrics. The system implements automatic export to Google Sheets for large datasets, recognizing that different result types require different presentation formats. These optimizations demonstrate attention to real-world usage patterns and infrastructure constraints.

The roadmap reveals ongoing LLMOps challenges and planned enhancements, including expanded system integrations, executive-level reliability requirements, and human-in-the-loop validation capabilities. The acknowledgment that the system "is not 100% reliable and is prone to hallucination" demonstrates realistic assessment of current LLM limitations, with planned human validation workflows for critical executive queries representing a pragmatic approach to managing AI reliability in high-stakes decision-making contexts.

However, the case study presentation shows characteristics of marketing content rather than objective technical documentation. Claims about performance improvements lack specific quantitative metrics, with statements like "within seconds" and "dramatically improves" not supported by concrete measurements. The comparison with other tools appears somewhat promotional, and third-party validation or independent assessment of the claimed benefits is not provided. Additionally, details about failure modes, error handling strategies, and specific accuracy metrics that would be expected in rigorous LLMOps documentation are limited.

Despite these limitations in the source material, the Finch implementation demonstrates several important LLMOps principles including modular architecture design, comprehensive evaluation frameworks, security-first implementation, and user-centered integration strategies. The system's approach to metadata enhancement, multi-agent orchestration, and continuous evaluation provides valuable insights for organizations implementing similar conversational AI systems for enterprise data access, though readers should seek additional technical validation beyond the promotional content provided.