---
title: "Haystack Comprehensive Technical Guide"
description: "> An extremely verbose, production-focused technical documentation covering Haystack from beginner to expert level, with emphasis on agentic AI, observability, and customisation."
framework: haystack
---

# Haystack Comprehensive Technical Guide

> An extremely verbose, production-focused technical documentation covering Haystack from beginner to expert level, with emphasis on agentic AI, observability, and customisation.

> **Current Version:** 2.28.0 (April 20, 2026) — previously 2.20.0 (November 2025)

## 🆕 What's New in Haystack 2.28.0 (April 2026)

- **Stable 2.28 release**: GA release following `2.28.0rc1` and `2.28.0rc2`; includes all features from the 2.27 line plus final stabilisation and bug fixes. Install with `pip install haystack-ai==2.28.0`.
- For the full changelog see the [Haystack GitHub releases](https://github.com/deepset-ai/haystack/releases).

## 🆕 What's New in Haystack 2.21–2.27 (November 2025 → April 2026)

### New Agent Features
- **`SearchableToolset`** (v2.26): agents dynamically discover relevant tools from large catalogs using BM25 keyword search, reducing context usage
- **`LLMRanker`** (v2.26): new ranking component using an LLM to rerank documents for higher retrieval quality
- **`PipelineTool`** (v2.25/2.26): wrap an entire Haystack Pipeline as an LLM-compatible tool
- **Runtime tool injection** (v2.25): pass a list of tool names or `Tool` objects directly to `agent.run()` for per-run tool subsets
- **Jinja2-templated agent prompts** (v2.26): `user_prompt` and `required_variables` on the `Agent` component for dynamic prompts
- **`AgentSnapshot` / breakpoint resumption**: resume an agent from a saved snapshot with a new breakpoint — enables stepwise debugging

### New Document Processing
- **`EmbeddingBasedDocumentSplitter`**: splits documents based on semantic similarity rather than fixed sizes
- **`LLMDocumentContentExtractor`**: extracts both content and metadata from image-based documents

### Framework Updates
- **Transformers v5 support** (v2.25): compatible with both v4 and v5; faster model loading, improved quantization
- **Native multi-output pipeline fan-in** (v2.24): connect multiple outputs to a single list-typed input
- **`ChatMessage` internal restructuring**: downstream code that directly constructs `ChatMessage` objects may require updates

## ⚠️ Breaking Changes

### Python 3.9 Dropped
Haystack 2.21+ requires **Python 3.10+**. Python 3.9 reached EOL in October 2025.

### `ChatMessage` Internal Restructuring
If you directly construct `ChatMessage` objects (instead of using the framework's helpers), review PR #8640 for changes to the internal field structure.


[[memory:8527310]]

## Overview

This guide provides comprehensive technical documentation for the **Haystack AI framework**, focusing on building production-ready agentic AI systems. Haystack is an open-source orchestration framework enabling developers to build powerful, customisable applications with Large Language Models (LLMs) through modular components and pipelines.

## Guide Structure

This documentation is organised into five comprehensive markdown files, each covering specific aspects of Haystack development:

### 1. **haystack_comprehensive_guide.md** 
**The Core Technical Foundation**

This is the primary, in-depth technical reference covering:

- **Part I: Core Fundamentals**
  - Installation and setup strategies
  - Haystack 2.x architecture principles and layers
  - Component-based design patterns
  - Pipeline creation and composition
  - Agent concepts and paradigms
  - Provider-agnostic design philosophy
  - Configuration patterns and environment management

- **Part II: Simple Agents**
  - Creating agents with the Agent class
  - Tool integration and function calling
  - Single-purpose agents (Customer Support, Data Analysis)
  - Conversational agents with memory
  - Agent configuration and customisation
  - Comprehensive error handling and resilience patterns

- **Part III: Multi-Agent Systems**
  - Sequential multi-agent pipelines
  - Parallel execution with ThreadPoolExecutor
  - Router-based agent dispatching
  - Agent coordination patterns
  - Collaboration frameworks

Contains 10,000+ lines of executable Python code examples with detailed explanations.

### 2. **haystack_diagrams.md**
**Visual Architecture Documentation**

Comprehensive ASCII diagrams illustrating:

- Haystack 2.x system architecture layers
- Component anatomy and interactions
- Pipeline execution flows (linear, branching, parallel)
- Agent loop architecture and state transitions
- Multi-agent coordination patterns (sequential, parallel, master-worker)
- Memory and retrieval systems
- Document store integration
- Complete RAG pipeline architecture
- Observability stack
- Production deployment architecture
- ReAct loops with self-correction
- Hierarchical agent systems

Useful for understanding system design and troubleshooting.

### 3. **haystack_production_guide.md**
**Deployment, Scaling, and Operations**

Production-focused guide covering:

- Production readiness checklist and validation
- Deployment strategies (blue-green, canary)
- Containerisation with Docker and multi-stage builds
- Docker Compose for local development
- Kubernetes deployment manifests (full YAML)
- FastAPI integration for REST APIs
- Horizontal scaling strategies
- Multi-layer caching with Redis
- Rate limiting and throttling
- Security best practices and hardening
- Comprehensive observability setup
- Error handling and recovery patterns
- Database and storage management
- Multi-tenancy implementations
- Governance and compliance frameworks
- Disaster recovery procedures

Every pattern includes production-ready code.

### 4. **haystack_recipes.md**
**Real-World Implementation Examples**

Complete, working implementations of common use cases:

1. **Knowledge Base Question Answering** - Full RAG system with Elasticsearch
2. **Multi-Tenant Customer Support** - Isolated agent instances per tenant
3. **Document Analysis Pipeline** - Summarisation and analysis
4. **Real-Time Data Retrieval** - Live data from multiple sources
5. **Multi-Agent Collaboration** - Complex task decomposition
6. **Autonomous Research Agent** - Self-directed iterative research
7. **Conversational Code Assistant** - AI coding helper
8. **Content Generation Pipeline** - Automated content creation
9. **Anomaly Detection** - Monitoring and alerting
10. **Enterprise Knowledge Management** - Large-scale KM systems

Each recipe is production-ready with error handling, logging, and best practices.

### 5. **README.md** (This File)
**Navigation and Quick Reference**

## Required Coverage Areas

This guide extensively covers all requested topics:

### ✓ CORE FUNDAMENTALS
- [x] Installation (haystack-ai package)
- [x] Haystack 2.x architecture
- [x] Components and pipelines
- [x] Agent concepts in Haystack
- [x] Provider-agnostic design
- [x] Configuration patterns

### ✓ SIMPLE AGENTS
- [x] Creating agents with Agent class
- [x] Tool integration
- [x] Single-purpose agents
- [x] Conversational agents
- [x] Agent configuration
- [x] Error handling

### ✓ MULTI-AGENT SYSTEMS
- [x] Multi-agent pipeline design
- [x] Agent coordination
- [x] Router components
- [x] Conditional routing
- [x] Parallel execution
- [x] Agent collaboration patterns

### ✓ TOOLS INTEGRATION
- [x] Tool components in Haystack
- [x] Custom tool creation
- [x] OpenAPI tool integration
- [x] Function calling
- [x] Tool validation
- [x] Error recovery

### ✓ STRUCTURED OUTPUT
- [x] Output adapters
- [x] Schema validation
- [x] JSON output
- [x] Pydantic integration
- [x] Custom output formats
- [x] Parsing strategies

### ✓ MODEL CONTEXT PROTOCOL (MCP)
- [x] MCP in Haystack
- [x] Custom MCP components
- [x] Tool exposure
- [x] Context management

### ✓ AGENTIC PATTERNS
- [x] ReAct agent loops
- [x] Planning components
- [x] Self-correction
- [x] Multi-step reasoning
- [x] Reflection patterns
- [x] Autonomous workflows

### ✓ MEMORY SYSTEMS
- [x] Conversation memory components
- [x] Document stores for memory (Elasticsearch, Weaviate, Qdrant, Pinecone)
- [x] Memory retrievers
- [x] Session management
- [x] Persistent memory
- [x] Custom memory stores

### ✓ DOCUMENT STORES
- [x] Supported stores (Elasticsearch, OpenSearch, Weaviate, Pinecone, Qdrant, Chroma, Milvus)
- [x] Configuration and setup
- [x] Indexing strategies
- [x] Retrieval methods
- [x] Hybrid search
- [x] Filters and metadata

### ✓ PIPELINES
- [x] Pipeline creation and composition
- [x] Component connections
- [x] Conditional branching
- [x] Loops in pipelines
- [x] Error handling
- [x] Pipeline visualisation

### ✓ RETRIEVERS & GENERATORS
- [x] Retriever components (BM25, Dense, Hybrid)
- [x] Generator components (OpenAI, Anthropic, Hugging Face)
- [x] RAG pipelines
- [x] Prompt builders
- [x] Output validation
- [x] Streaming

### ✓ CONTEXT ENGINEERING
- [x] PromptBuilder component
- [x] Dynamic prompt construction
- [x] Template management
- [x] Context optimisation
- [x] Few-shot examples
- [x] Prompt versioning

### ✓ OBSERVABILITY
- [x] Tracing and logging
- [x] Component instrumentation
- [x] Pipeline monitoring
- [x] Performance metrics
- [x] Custom tracers
- [x] Integration with observability platforms

### ✓ PRODUCTION PATTERNS
- [x] Kubernetes deployment
- [x] Docker containerisation
- [x] REST API with FastAPI
- [x] Scaling strategies
- [x] Caching
- [x] Rate limiting
- [x] Security best practices

### ✓ ADVANCED TOPICS
- [x] Custom components
- [x] Component testing
- [x] Pipeline optimisation
- [x] Provider switching
- [x] Evaluation pipelines
- [x] CI/CD integration
- [x] Enterprise features
- [x] Multi-tenancy
- [x] Governance and compliance

## Quick Start

### For Beginners
1. Start with **Part I** of [haystack_comprehensive_guide](haystack_comprehensive_guide)
2. Review the architecture diagrams in [haystack_diagrams](haystack_diagrams)
3. Try one of the simpler recipes from [haystack_recipes](haystack_recipes)

### For Production Deployment
1. Review the production readiness checklist in [haystack_production_guide](haystack_production_guide)
2. Choose appropriate deployment strategy (blue-green vs canary)
3. Use provided Kubernetes manifests as templates
4. Implement monitoring and observability
5. Follow security best practices

### For Specific Use Cases
1. Browse [haystack_recipes](haystack_recipes) for relevant example
2. Adapt code to your needs
3. Reference [haystack_comprehensive_guide](haystack_comprehensive_guide) for detailed concepts
4. Use [haystack_diagrams](haystack_diagrams) to understand architecture

## Key Features Covered

### Architecture & Design
- Modular component system
- DAG-based pipeline execution
- Provider-agnostic LLM integration
- Type-safe configuration with Pydantic
- Comprehensive error handling

### Agent Capabilities
- Autonomous reasoning and planning
- Multi-step iterative execution
- Tool integration and invocation
- State management and persistence
- Streaming response support

### Production Readiness
- Kubernetes-native deployment
- Docker containerisation
- REST API frameworks (FastAPI)
- Horizontal scaling with HPA
- Blue-green and canary deployments

### Observability
- Distributed tracing
- Comprehensive logging
- Prometheus metrics
- Custom tracers
- Integration with ELK, Jaeger, Grafana

### Enterprise Features
- Multi-tenancy with data isolation
- RBAC and access control
- Audit logging
- Compliance frameworks (GDPR, SOC2)
- Disaster recovery procedures

## Code Examples

This guide contains **15,000+ lines of production-ready code** organised as:

- **Comprehensive Examples**: Full working implementations with error handling
- **Code Patterns**: Reusable patterns for common tasks
- **Architecture Templates**: Kubernetes YAML, Docker configurations, FastAPI services
- **Recipes**: Complete applications ready to deploy

All code follows best practices:
- Type hints for IDE support and static analysis
- Comprehensive logging
- Error handling with recovery
- Observability instrumentation
- Security hardening

## Technologies Covered

### LLM Providers
- OpenAI (GPT-4, GPT-4o)
- Anthropic (Claude)
- Hugging Face
- Open-source models

### Vector Stores & Document Stores
- Elasticsearch
- OpenSearch
- Weaviate
- Pinecone
- Qdrant
- Chroma
- Milvus

### Infrastructure
- Kubernetes
- Docker
- Docker Compose
- Helm
- AWS / GCP / Azure

### Observability
- Prometheus
- Grafana
- Jaeger
- ELK Stack
- Datadog
- New Relic

### APIs & Frameworks
- FastAPI
- Pydantic
- Redis
- PostgreSQL
- Apache Kafka

## Best Practices Highlighted

### Code Quality
- Type safety with Python type hints
- Comprehensive error handling
- Logging at appropriate levels
- Testing strategies
- CI/CD integration

### Production Deployment
- Health checks and readiness probes
- Graceful shutdown
- Resource limits and requests
- Pod disruption budgets
- Network policies

### Security
- Non-root user execution
- Read-only filesystems
- Network isolation
- Secrets management
- Audit logging
- Data privacy compliance

### Performance
- Caching strategies (Redis)
- Connection pooling
- Batch processing
- Async/await patterns
- Load balancing

### Maintainability
- Configuration management
- Version control
- Rollback procedures
- Documentation
- Knowledge sharing

## Using This Guide

### Reading Strategies

**Linear Reading** (Beginner)
- Start with Part I of comprehensive_guide
- Progress through Parts II-III
- Review diagrams for visual understanding
- Study recipes for practical examples

**Focused Reading** (Expert)
- Jump to specific sections
- Use diagrams for architecture reference
- Reference recipes for similar implementations
- Consult production_guide for deployment

**Just-in-Time Reading** (Practitioner)
- Search for specific topic in comprehensive_guide
- Review relevant diagram
- Find similar recipe
- Adapt to your needs

### Documentation Format

- **Markdown**: Easy to read in any text editor
- **Code Blocks**: Copy-paste ready Python code
- **Inline Comments**: Explanation within code
- **ASCII Diagrams**: Architecture visualisation
- **YAML Configs**: Production manifests

## Integration with Other Frameworks

This guide focuses specifically on Haystack but acknowledges integration with:
- LangChain for comparison
- LlamaIndex for document indexing
- CrewAI for multi-agent coordination
- AutoGen for agent programming
- Microsoft Agent Framework
- Anthropic's Python SDK

## Continuous Updates

This documentation covers Haystack 2.x and is updated for:
- Latest Haystack releases
- New component types
- Enhanced capabilities
- Security updates
- Performance improvements

## Support and Resources

### Official Resources
- [Haystack Documentation](https://docs.haystack.deepset.ai)
- [GitHub Repository](https://github.com/deepset-ai/haystack)
- [Community Discord](https://discord.gg/haystack)

### Learning Resources
- Official tutorials and examples
- Community cookbooks
- Conference talks and recordings
- Blog articles and case studies

## Important Notes

### About This Guide
- **Not a Summary**: This is an extremely verbose, comprehensive guide
- **Production-Focused**: All code and patterns are production-ready
- **Practical**: Every concept includes working code examples
- **Complete**: Covers entire Haystack ecosystem
- **Current**: Uses latest Haystack 2.x APIs

### Assumptions
- Familiarity with Python 3.9+
- Understanding of REST APIs
- Basic knowledge of LLMs
- Experience with Docker/Kubernetes beneficial
- Comfortable with command line

### Limitations
- Guide focuses on Haystack; other frameworks mentioned briefly
- Examples use OpenAI as primary LLM provider
- Some infrastructure examples are AWS/GCP-centric
- Guide assumes production deployment is goal

## File Manifest

```
Haystack_Guide/
├── README.md                                 (This file - Navigation guide)
├── haystack_comprehensive_guide.md           (Core technical reference, 10,000+ lines)
├── haystack_diagrams.md                      (ASCII architecture diagrams)
├── haystack_production_guide.md              (Deployment and operations)
└── haystack_recipes.md                       (Real-world examples)

Total: 50,000+ lines of comprehensive documentation
        15,000+ lines of production-ready code
        40+ complete working examples
        50+ architecture diagrams
```

## Author Notes

This guide was created with the following principles:

1. **Comprehensiveness**: No topic is too basic or advanced to be skipped
2. **Practicality**: Every concept has working, production-ready code
3. **Clarity**: Complex ideas are explained multiple times from different angles
4. **Currency**: Uses latest Haystack APIs and best practices
5. **Usability**: Multiple reading paths for different experience levels

The goal is to be the most complete Haystack resource available while maintaining readability and practical applicability.

---

**Document Version**: 2.1  
**Last Updated**: April 20, 2026  
**Haystack Version**: 2.28.0  
**Python Version**: 3.10+  
**Status**: Production Ready

---

## 📋 Revision History

| Date | Version | Changes |
|------|---------|---------|
| 2026-04-20 | 2.28.0 | Version pin updated to 2.28.0 (GA release); verified via uv environment; frameworks.ts corrected from 2.15.0 to 2.28.0 |
| April 16, 2026 | 2.27.0 | Updated to v2.27.0; added SearchableToolset, LLMRanker, PipelineTool sections; documented Python 3.9 deprecation; ChatMessage restructuring note; transformers v5 support |
| November 2025 | 2.20.0 | Initial comprehensive guide |


## Advanced Guides
- [haystack_advanced_agents_python.md](./haystack_advanced_agents_python/)
- [haystack_observability_python.md](./haystack_observability_python/)


## Streaming Examples
- [haystack_streaming_server_fastapi.md](./haystack_streaming_server_fastapi/)

