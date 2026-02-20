---
ai_commentary: []
ai_commentary_meta:
  content_digest: ''
  generated_at: ''
  model: ''
  prompt_version: ''
  provider: ''
category: ai-research
date: '2026-02-20T08:15:35.500046+00:00'
exported_at: '2026-02-20T08:15:37.761353+00:00'
feed: https://aws.amazon.com/blogs/machine-learning/feed
language: en
source_url: https://aws.amazon.com/blogs/machine-learning/build-unified-intelligence-with-amazon-bedrock-agentcore
structured_data:
  about: []
  author: ''
  description: In this post, we demonstrate how to build unified intelligence systems
    using Amazon Bedrock AgentCore through our real-world implementation of the Customer
    Agent and Knowledge Engine (CAKE).
  headline: Build unified intelligence with Amazon Bedrock AgentCore
  inLanguage: en
  keywords: []
  main_image: ''
  original_source: https://aws.amazon.com/blogs/machine-learning/build-unified-intelligence-with-amazon-bedrock-agentcore
  publisher:
    logo: /favicon.ico
    name: gtcode.com
title: Build unified intelligence with Amazon Bedrock AgentCore
updated_at: '2026-02-20T08:15:35.500046+00:00'
url_hash: 47387120b672789917ba96d23a10231d7bcfe69c
---

Building cohesive and unified customer intelligence across your organization starts with reducing the friction your sales representatives face when toggling between Salesforce, support tickets, and Amazon Redshift. A sales representative preparing for a customer meeting might spend hours clicking through several different dashboards—product recommendations, engagement metrics, revenue analytics, etc. – before developing a complete picture of the customer’s situation. At AWS, our sales organization experienced this firsthand as we scaled globally. We needed a way to unify siloed customer data across metrics databases, document repositories, and external industry sources – without building complex custom orchestration infrastructure.

We built the Customer Agent & Knowledge Engine (CAKE), a customer centric chat agent using
[Amazon Bedrock AgentCore](https://aws.amazon.com/bedrock/agentcore/)
to solve this challenge. CAKE coordinates specialized retriever tools – querying knowledge graphs in
[Amazon Neptune](https://aws.amazon.com/neptune/)
, metrics in
[Amazon DynamoDB](https://aws.amazon.com/dynamodb/)
, documents in
[Amazon OpenSearch](https://aws.amazon.com/opensearch-service/)
Service, and external market data using a web search API, along with security enforcement using Row Level Security tool (RLS), delivering customer insights through natural language queries in under 10 seconds (as observed in agent load tests).

In this post, we demonstrate how to build unified intelligence systems using Amazon Bedrock AgentCore through our real-world implementation of CAKE. You can build custom agents that unlock the following features and benefits:

* Coordination of specialized tools through dynamic intent analysis and parallel execution
* Integration of purpose-built data stores (Neptune, DynamoDB, OpenSearch Service) with parallel orchestration
* Implementation of row-level security and governance within workflows
* Production engineering practices for reliability, including template-based reporting to adhere to business semantic and style
* Performance optimization through model flexibility

These architectural patterns can help you accelerate development for different use cases, including customer intelligence systems, enterprise AI assistants, or multi-agent systems that coordinate across different data sources.

## Why customer intelligence systems need unification

As sales organizations scale globally, they often face three critical challenges: fragmented data across specialized tools (product recommendations, engagement dashboards, revenue analytics, etc.) requiring hours to gather comprehensive customer views, loss of business semantics in traditional databases that can’t capture semantic relationships explaining why metrics matter, and manual consolidation processes that can’t scale with growing data volumes. You need a unified system that can aggregate customer data, understand semantic relationships, and reason through customer needs in business context, making CAKE the essential linchpin for enterprises everywhere.

## Solution overview

CAKE is a customer-centric chat agent that transforms fragmented data into unified, actionable intelligence. By consolidating internal and external data sources/tables into a single conversational endpoint, CAKE delivers personalized customer insights powered by context-rich knowledge graphs—all in under 10 seconds. Unlike traditional tools that simply report numbers, the semantic foundation of CAKE captures the meaning and relationships between business metrics, customer behaviors, industry dynamics, and strategic contexts. This enables CAKE to explain not just what is happening with a customer, but why it’s happening and how to act.

Amazon Bedrock AgentCore provides the runtime infrastructure that multi-agent AI systems require as a managed service, including inter-agent communication, parallel execution, conversation state tracking, and tool routing. This helps teams focus on defining agent behaviors and business logic rather than implementing distributed systems infrastructure.

For CAKE, we built a custom agent on Amazon Bedrock AgentCore that coordinates five specialized tools, each optimized for different data access patterns:

* Neptune retriever tool for graph relationship queries
* DynamoDB agent for instant metric lookups
* OpenSearch retriever tool for semantic document search
* Web search tool for external industry intelligence
* Row level security (RLS) tool for security enforcement

The following diagram shows how Amazon Bedrock AgentCore supports the orchestration of these components.

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2026/01/20/ML-20135-image-1.png)

The solution flows through several key phases in response to a question (for example, “What are the top expansion opportunities for this customer?”):

* **Analyzes intent and routes the query**
  – The supervisor agent, running on Amazon Bedrock AgentCore, analyzes the natural language query to determine its intent. The question requires customer understanding, relationship data, usage metrics, and strategic insights. The agent’s tool-calling logic, using Amazon Bedrock AgentCore Runtime, identifies which specialized tools to activate.
* **Dispatches tools in parallel**
  – Rather than executing tool calls sequentially, the orchestration layer dispatches multiple retriever tools in parallel, using the scalable execution environment of Amazon Bedrock AgentCore Runtime. The agent manages the execution lifecycle, handling timeouts, retries, and error conditions automatically.
* **Synthesizes multiple results**
  – As specialized tools return results, Amazon Bedrock AgentCore streams these partial responses to the supervisor agent, which synthesizes them into a coherent answer. The agent reasons about how different data sources relate to each other, identifies patterns, and generates insights that span multiple knowledge domains.
* **Enforces security boundaries**
  – Before data retrieval begins, the agent invokes the RLS tool to deterministically enforce user permissions. The custom agent then verifies that subsequent tool calls respect these security boundaries, automatically filtering results and helping prevent unauthorized data access. This security layer operates at the infrastructure level, reducing the risk of implementation errors.

This architecture operates on two parallel tracks: Amazon Bedrock AgentCore provides the runtime for the real-time serving layer that responds to user queries with minimal latency, and an offline data pipeline periodically refreshes the underlying data stores from the analytical data warehouse. In the following sections, we discuss the agent framework design and core solution components, including the knowledge graph, data stores, and data pipeline.

## **Agent framework design**

Our multi-agent system leverages the AWS Strands Agents framework to deliver structured reasoning capabilities while maintaining the enterprise controls required for regulatory compliance and predictable performance. The multi-agent system is built on the AWS Strands Agents framework, which provides a model-driven foundation for building agents from many different models. The supervisor agent analyzes incoming questions to intelligently select which specialized agents and tools to invoke and how to decompose user queries. The framework exposes agent states and outputs to implement decentralized evaluation at both agent and supervisor levels. Building on model-driven approach, we implement agentic reasoning through GraphRAG reasoning chains that construct deterministic inference paths by traversing knowledge relationships. Our agents perform autonomous reasoning within their specialized domains, grounded around pre-defined ontologies while maintaining predictable, auditable behavior patterns required for enterprise applications.

The supervisor agent employs a multi-phase selection protocol:

* **Question analysis**
  – Parse and understand user intent
* **Source selection**
  – Intelligent routing determines which combination of tools are needed
* **Query decomposition**
  – Original questions are broken down into specialized sub-questions optimized for each selected tool
* **Parallel execution**
  – Selected tools execute concurrently through serverless AWS Lambda action groups

Tools are exposed through a hierarchical composition pattern (accounting for data modality—structured vs. unstructured) where high-level agents and tools coordinate multiple specialized sub-tools:

* **Graph reasoning tool**
  – Manages entity traversal, relationship analysis, and knowledge extraction
* **Customer insights agent**
  – Coordinates multiple fine-tuned models in parallel for generating customer summaries from tables
* **Semantic search tool**
  – Orchestrates unstructured text analysis (such as field notes)
* **Web research tool**
  – Coordinates web/news retrieval

We extend the core AWS Strands Agents framework with enterprise-grade capabilities including customer access validation, token optimization, multi-hop LLM selection for model throttling resilience, and structured GraphRAG reasoning chains. These extensions deliver the autonomous decision-making capabilities of modern agentic systems while facilitating predictable performance and regulatory compliance alignment.

## Building the knowledge graph foundation

CAKE’s knowledge graph in Neptune represents customer relationships, product usage patterns, and industry dynamics in a structured format that empowers AI agents to perform efficient reasoning. Unlike traditional databases that store information in isolation, CAKE’s knowledge graph captures the semantic meaning of business entities and their relationships.

### Graph construction and entity modeling

We designed the knowledge graph around AWS sales ontology—the core entities and relationships that sales teams discuss daily:

* **Customer entities**
  – With properties extracted from data sources including industry classifications, revenue metrics, cloud adoption phase, and engagement scores
* **Product entities**
  – Representing AWS services, with connections to use cases, industry applications, and customer adoption patterns
* **Solution entities –**
  Linking products to business outcomes and strategic initiatives
* **Opportunity entities**
  – Tracking sales pipeline, deal stages, and associated stakeholders
* **Contact entities**
  – Mapping relationship networks within customer organizations

Amazon Neptune excels at answering questions that require understanding connections—finding how two entities are related, identifying paths between accounts, or discovering indirect relationships that span multiple hops. The offline data construction process runs scheduled queries against Redshift clusters to prepare data to be loaded in the graph.

### Capturing relationship context

CAKE’s knowledge graph captures how relationships connect entities. When the graph connects a customer to a product through an increased usage relationship, it also stores contextual attributes: the rate of increase, the business driver (from account plans), and related product adoption patterns. This contextual richness helps the LLM understand business context and provide explanations grounded in actual relationships rather than statistical correlation alone.

### Purpose-built data stores

Rather than storing data in a single database, CAKE uses specialized data stores, each designed for how it gets queried. Our custom agent, running on Amazon Bedrock AgentCore, manages the coordination across these stores—sending queries to the right database, running them at the same time, and combining results—so both users and developers work with what feels like a single data source:

* **Neptune for graph relationships**
  – Neptune stores the web of connections between customers, accounts, stakeholders, and organizational entities. Neptune excels at multi-hop traversal queries that require expensive joins in relational databases—finding relationship paths between disconnected accounts, or discovering customers in an industry who’ve adopted specific AWS services. When Amazon Bedrock AgentCore identifies a query requiring relationship reasoning, it automatically routes to the Neptune retriever tool.
* **DynamoDB for instant metrics**
  – DynamoDB operates as a key-value store for precomputed aggregations. Rather than computing customer health scores or engagement metrics on-demand, the offline pipeline pre-computes these values and stores them indexed by customer ID. DynamoDB then delivers sub-10ms lookups, enabling instant report generation. Tool chaining in Amazon Bedrock AgentCore allows it to retrieve metrics from DynamoDB, pass them to the magnifAI agent (our custom table-to-text agent) for formatting, and return polished reports—all without custom integration code.
* **OpenSearch Service for semantic document search**
  – OpenSearch Service stores unstructured content like account plans and field notes. Using embedding models, OpenSearch Service converts text into vector representations that support semantic matching. When Amazon Bedrock AgentCore receives a query about “digital transformation,” for example, it recognizes the need for semantic search and automatically routes to the OpenSearch Service retriever tool, which finds relevant passages even when documents use different terminology.
* **S3 for document storage**
  – Amazon Simple Storage Service (Amazon S3) provides the foundation for OpenSearch Service. Account plans are stored as Parquet files in Amazon S3 before being indexed because the source warehouse (Amazon Redshift) has truncation limits that would cut off large documents. This multi-step process—Amazon S3 storage, embedding generation, OpenSearch Service indexing—preserves complete content while maintaining the low latency required for real-time queries.

Building on Amazon Bedrock AgentCore makes these multi-database queries feel like a single, unified data source. When a query requires customer relationships from Neptune, metrics from DynamoDB, and document context from OpenSearch Service, our agent automatically dispatches requests to all three in parallel, manages their execution, and synthesizes their results into a single coherent response.

### Data pipeline and continuous refresh

The CAKE offline data pipeline operates as a batch process that runs on a scheduled cadence to keep the serving layer synchronized with the latest business data. The pipeline architecture separates data construction from data serving, so the real-time query layer can maintain low latency while the batch pipeline handles computationally intensive aggregations and graph construction.

The Data Processing Orchestration layer coordinates transformations across multiple target databases. For each database, the pipeline performs the following steps:

* Extracts relevant data from Amazon Redshift using optimized queries
* Applies business logic transformations specific to each data store’s requirements
* Loads processed data into the target database with appropriate indexes and partitioning

For Neptune, this involves extracting entity data, constructing graph nodes and edges with property attributes, and loading the graph structure with semantic relationship types. For DynamoDB, the pipeline computes aggregations and metrics, structures data as key-value pairs optimized for customer ID lookups, and applies atomic updates to maintain consistency. For OpenSearch Service, the pipeline follows a specialized path: large documents are first exported from Amazon Redshift to Amazon S3 as Parquet files, then processed through embedding models to generate vector representations, which are finally loaded into the OpenSearch Service index with appropriate metadata for filtering and retrieval.

## **Engineering for production: Reliability and accuracy**

When transitioning CAKE from prototype to production, we implemented several critical engineering practices to facilitate reliability, accuracy, and trust in AI-generated insights.

### **Model flexibility**

The Amazon Bedrock AgentCore architecture decouples the orchestration layer from the underlying LLM, allowing flexible model selection. We implemented model hopping to provide automatic fallback to alternative models when throttling occurs. This resilience happens transparently within AgentCore’s Runtime—detecting throttling conditions, routing requests to available models, and maintaining response quality without user-visible degradation.

### **Row-Level Security (RLS) and Data Governance**

Before data retrieval occurs, the RLS tool enforces row-level security based on user identity and organizational hierarchy. This security layer operates transparently to users while maintaining strict data governance:

* Sales representatives access only customers assigned to their territories
* Regional managers view aggregated data across their regions
* Executives have broader visibility aligned with their responsibilities

The RLS tool routes queries to appropriate data partitions and applies filters at the database query level, so security can be enforced in the data layer rather than relying on application-level filtering.

## Results and impact

CAKE has transformed how AWS sales teams access and act on customer intelligence. By providing instant access to unified insights through natural language queries, CAKE reduces the time spent searching for information from hours to seconds as per surveys/feedback from users, helping sales representatives focus on strategic customer engagement rather than data gathering.

The multi-agent architecture delivers query responses in seconds for most queries, with the parallel execution model supporting simultaneous data retrieval from multiple sources. The knowledge graph enables sophisticated reasoning that goes beyond simple data aggregation—CAKE explains why trends occur, identifies patterns across seemingly unrelated data points, and generates recommendations grounded in business relationships. Perhaps most importantly, CAKE democratizes access to customer intelligence across the organization. Sales representatives, account managers, solutions architects, and executives interact with the same unified system, providing consistent customer insights while maintaining appropriate security and access controls.

## Conclusion

In this post, we showed how
[Amazon Bedrock AgentCore](https://aws.amazon.com/bedrock/agentcore/)
supports CAKE’s multi-agent architecture. Building multi-agent AI systems traditionally requires significant infrastructure investment, including implementing custom agent coordination protocols, managing parallel execution frameworks, tracking conversation state, handling failure modes, and building security enforcement layers. Amazon Bedrock AgentCore reduces this undifferentiated heavy lifting by providing these capabilities as managed services within Amazon Bedrock.

Amazon Bedrock AgentCore provides the runtime infrastructure for orchestration, and specialized data stores excel at their specific access patterns. Neptune handles relationship traversal, DynamoDB provides instant metric lookups, and OpenSearch Service supports semantic document search, but our custom agent, built on Amazon Bedrock AgentCore, coordinates these components, automatically routing queries to the right tools, executing them in parallel, synthesizing their results, and maintaining security boundaries throughout the workflow. The CAKE experience demonstrates how Amazon Bedrock AgentCore can help teams build multi-agent AI systems, speeding up the process from months of infrastructure development to weeks of business logic implementation. By providing orchestration infrastructure as a managed service, Amazon Bedrock AgentCore helps teams focus on domain expertise and customer value rather than building distributed systems infrastructure from scratch.

To learn more about Amazon Bedrock AgentCore and building multi-agent AI systems, refer to the
[Amazon Bedrock User Guide](https://docs.aws.amazon.com/bedrock-agentcore/latest/devguide/agentcore-get-started-toolkit.html)
,
[Amazon Bedrock Workshop](https://www.workshops.aws/categories/AgentCore)
, and
[Amazon Bedrock Agents](https://aws.amazon.com/blogs/machine-learning/move-your-ai-agents-from-proof-of-concept-to-production-with-amazon-bedrock-agentcore/)
. For the latest news on AWS, see
[What’s New with AWS](https://aws.amazon.com/new/)
.

**Acknowledgments**

We extend our sincere gratitude to our executive sponsors and mentors whose vision and guidance made this initiative possible:
[Aizaz Manzar](https://www.linkedin.com/in/aizazmanzar/)
, Director of AWS Global Sales;
[Ali Imam](https://www.linkedin.com/in/aliimam27/)
, Head of Startup Segment; and
[Akhand Singh](https://www.linkedin.com/in/akhand17/)
, Head of Data Engineering.

We also thank the dedicated team members whose technical expertise and contributions were instrumental in bringing this product to life:
[Aswin Palliyali Venugopalan](https://www.linkedin.com/in/aswinpvenugopalan/)
, Software Dev Manager;
[Alok Singh](https://www.linkedin.com/in/salok19/)
, Senior Software Development Engineer;
[Muruga Manoj Gnanakrishnan](https://www.linkedin.com/in/muruga-manoj-g-1138aa62/)
, Principal Data Engineer;
[Sai Meka](https://www.linkedin.com/in/ravichandra-meka/)
, Machine Learning Engineer;
[Bill Tran](https://www.linkedin.com/in/billtran236/)
, Data Engineer; and
[Rui Li](https://www.linkedin.com/in/ruili2011/)
, Applied Scientist.

---

### About the authors

**![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2026/01/20/ML-20135-image-2-1.jpeg)
Monica Jain**
is a Senior Technical Product Manager at AWS Global Sales and an analytics professional driving AI-powered sales intelligence at scale. She leads the development of generative AI and ML-powered data products—including knowledge graphs, AI-augmented analytics, natural language query systems, and recommendation engines, that improve seller productivity and decision-making. Her work enables AWS executives and sellers worldwide to access real-time insights and accelerate data-driven customer engagement and revenue growth.

**![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2026/01/20/ML-20135-image-3-1.jpeg)
M. Umar Javed**
is a Senior Applied Scientist at AWS, with over 8 years of experience across academia and industry and a PhD in ML theory. At AWS, he builds production-grade generative AI and machine learning solutions, with work spanning multi-agent LLM architectures, research on small language models, knowledge graphs, recommendation systems, reinforcement learning, and multi-modal deep learning. Prior to AWS, Umar contributed to ML research at NREL, CISCO, Oxford, and UCSD. He is a recipient of the ECEE Excellence Award (2021) and contributed to two Donald P. Eckman Awards (2021, 2023).

**![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2026/01/20/ML-20135-image-4-1.jpeg)
Damien Forthomme**
is a Senior Applied Scientist at AWS, leading a Data Science team in AWS Sales, Marketing, and Global Services (SMGS). With more than 10 years of experience and a PhD in Physics, he focuses on using and building advanced machine learning and generative AI tools to surface the right data to the right people at the right time. His work encompasses initiatives such as forecasting, recommendation systems, core foundational datasets creation, and building generative AI products that enhance sales productivity for the organization.

**![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2026/01/20/ML-20135-image-5-1.jpeg)
Mihir Gadgil**
is a Senior Data Engineer in AWS Sales, Marketing, and Global Services (SMGS), specializing in enterprise-scale data solutions and generative AI applications. With over 9 years of experience and a Master’s in Information Technology & Management, he focuses on building robust data pipelines, complex data modeling, and ETL/ELT processes. His expertise drives business transformation through innovative data engineering solutions and advanced analytics capabilities.

**![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2026/01/20/ML-20135-image-6-1.png)
Sujit Narapareddy**
, Head of Data & Analytics at AWS Global Sales, is a technology leader driving global enterprise transformation. He leads data product and platform teams that power the AWS’s Go-to-Market through AI-augmented analytics and intelligent automation. With a proven track record in enterprise solutions, he has transformed sales productivity, data governance, and operational excellence. Previously at JPMorgan Chase Business Banking, he shaped next-generation FinTech capabilities through data innovation.

**![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2026/01/21/normbrad--100x100.jpg)
Norman Braddock**
, Senior Manager of AI Product Management at AWS, is a product leader driving the transformation of business intelligence through agentic AI. He leads the Analytics & Insights Product Management team within Sales, Marketing, and Global Services (SMGS), delivering products that bridge AI model performance with measurable business impact. With a background spanning procurement, manufacturing, and sales operations, he combines deep operational expertise with product innovation to shape the future of autonomous business management.