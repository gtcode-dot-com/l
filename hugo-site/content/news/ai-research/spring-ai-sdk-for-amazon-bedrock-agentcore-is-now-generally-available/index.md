---
ai_commentary: []
ai_commentary_meta:
  content_digest: ''
  generated_at: ''
  model: ''
  prompt_version: ''
  provider: ''
category: ai-research
date: '2026-04-14T14:15:46.113812+00:00'
exported_at: '2026-04-14T14:15:48.736105+00:00'
feed: https://aws.amazon.com/blogs/machine-learning/feed
language: en
source_url: https://aws.amazon.com/blogs/machine-learning/spring-ai-sdk-for-amazon-bedrock-agentcore-is-now-generally-available
structured_data:
  about: []
  author: ''
  description: With the new Spring AI AgentCore SDK, you can build production-ready
    AI agents and run them on the highly scalable AgentCore Runtime. The Spring AI
    AgentCore SDK is an open source library that brings Amazon Bedrock AgentCore capabilities
    into Spring AI. In this post, we build an AI agent starting with a chat endpoin...
  headline: Spring AI SDK for Amazon Bedrock AgentCore is now Generally Available
  inLanguage: en
  keywords: []
  main_image: ''
  original_source: https://aws.amazon.com/blogs/machine-learning/spring-ai-sdk-for-amazon-bedrock-agentcore-is-now-generally-available
  publisher:
    logo: /favicon.ico
    name: GTCode
title: Spring AI SDK for Amazon Bedrock AgentCore is now Generally Available
updated_at: '2026-04-14T14:15:46.113812+00:00'
url_hash: d20fe9c65b102543fb3017381768772faa9aa43e
---

Agentic AI is transforming how organizations use generative AI, moving beyond prompt-response interactions to autonomous systems that can plan, execute, and complete complex multi-step tasks. While early proof of concepts in Agentic AI spaces
excite business stakeholders, scaling them to production requires addressing scalability, governance, and security challenges.
[Amazon Bedrock AgentCore](https://aws.amazon.com/bedrock/agentcore/)
is an Agentic AI platform to build, deploy, and operate agents at scale using any framework and any model.

Java developers want to build AI agents using known Spring patterns, but production deployment requires infrastructure that’s complex to implement from scratch. Amazon Bedrock AgentCore provides building blocks like managed runtime infrastructure (scalability, reliability, security, observability), short- and long-term memory, browser automation, sandboxed code execution, and evaluations. Integrating these capabilities into a Spring application currently requires writing custom controllers to fulfill AgentCore Runtime contract, handling Server-Side Events (SSE) streaming, implementing health checks, managing rate limiting, and wiring up Spring advisors, memory repositories, and tool definitions. This is weeks of infrastructure work before writing any AI Agent logic.

With the new
[Spring AI AgentCore SDK](https://github.com/spring-ai-community/spring-ai-agentcore)
, you can build production-ready AI agents and run them on the highly scalable AgentCore Runtime. The Spring AI AgentCore SDK is an open source library that brings Amazon Bedrock AgentCore capabilities into
[Spring AI](https://spring.io/projects/spring-ai)
through known patterns: annotations, auto-configuration, and composable advisors. SpringAI Builders add a dependency, annotate a method, and the SDK handles the rest.

## Understanding the AgentCore Runtime contract

[AgentCore Runtime](https://docs.aws.amazon.com/bedrock-agentcore/latest/devguide/agents-tools-runtime.html)
manages agent lifecycle and scaling with pay-per-use pricing, meaning you don’t pay for idle compute. The runtime routes incoming requests to your agent and monitors its health, but this requires your agent to follow a contract. The contract requires that the implementation exposes two endpoints. The
**/invocations**
endpoint receives requests and returns responses as either JSON or SSE streaming. The
**/ping**
health endpoint reports a Healthy or HealthyBusy status. Long-running tasks must signal that they’re busy, or the runtime might scale them down to save costs. The SDK implements this contract automatically, including async task detection that reports
[busy status](https://docs.aws.amazon.com/bedrock-agentcore/latest/devguide/runtime-long-run.html)
when your agent is processing.

Beyond the contract, the SDK provides additional capabilities for production workloads like handling SSE responses with proper framing, backpressure handling, and connection lifecycle management for large responses. It also provides rate limiting, throttling requests to protect your agent from traffic spikes and limit per-user consumption. You focus is on agent logic while the SDK handles the runtime integration.Beyond the contract, the SDK provides additional capabilities for production workloads such as handling SSE responses with proper framing, backpressure handling, and connection lifecycle management for large responses. It also provides rate limiting, throttling requests to protect your agent from traffic spikes and limit per-user consumption. You focus on agent logic while the SDK handles the runtime integration.

In this post, we build a production-ready AI agent starting with a chat endpoint, then adding streaming responses, conversation memory, and tools for web browsing and code execution. By the end, you will have a fully functional agent ready to deploy to AgentCore Runtime or run standalone on your existing infrastructure.

## Prerequisites

To follow along, you need:

## Solution overview

The Spring AI AgentCore SDK is built on three design principles:

* **Convention over configuration**
  – Sensible defaults align with AgentCore expectations (port 8080, endpoint paths, content-type handling) without explicit configuration.
* **Annotation-driven development**
  – A single @AgentCoreInvocation annotation transforms any
  [Spring bean](https://docs.spring.io/spring-framework/reference/core/beans/definition.html)
  method into an AgentCore-compatible endpoint with automatic serialization, streaming detection, and response formatting.
* **Deployment flexibility**
  – The SDK supports
  [AgentCore Runtime](https://docs.aws.amazon.com/bedrock-agentcore/latest/devguide/agents-tools-runtime.html)
  for fully managed deployment, but you can also use individual modules (
  [Memory](https://docs.aws.amazon.com/bedrock-agentcore/latest/devguide/memory.html)
  ,
  [Browser](https://docs.aws.amazon.com/bedrock-agentcore/latest/devguide/browser-tool.html)
  ,
  [Code Interpreter](https://docs.aws.amazon.com/bedrock-agentcore/latest/devguide/code-interpreter-tool.html)
  ) in applications running on
  [Amazon EKS](https://aws.amazon.com/eks/)
  ,
  [Amazon ECS](https://aws.amazon.com/ecs/)
  , or any other infrastructure.

The following diagram shows how the SDK components interact. The @AgentCoreInvocation annotation handles the runtime contract, while the ChatClient composes Memory advisors, Browser tools, and Code Interpreter. Deployment to AgentCore Runtime is optional. You can use the SDK modules as standalone features.

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2026/04/13/ml-19946-image-1.jpeg)

## Creating your first AI agent

The following section walks you through how to create a fully functional agent step by step:

### Step 1: Add the SDK dependency

Add the Spring AI AgentCore BOM to your Maven project, then include the runtime starter:

```
<dependencyManagement>
<dependencies>
<dependency>
<groupId>org.springaicommunity</groupId>
<artifactId>spring-ai-agentcore-bom</artifactId>
<version>1.0.0</version>
<type>pom</type>
<scope>import</scope>
</dependency>
</dependencies>
</dependencyManagement>

<dependencies>
<dependency>
<groupId>org.springaicommunity</groupId>
<artifactId>spring-ai-agentcore-runtime-starter</artifactId>
</dependency>
</dependencies>
```

### Step 2: Create the agent

The @AgentCoreInvocation annotation tells the SDK that this method handles incoming agent requests. The SDK auto-configures POST /invocations and GET /ping endpoints, handles JSON serialization, and reports health status automatically.

```
@Service
public class MyAgent {

private final ChatClient chatClient;

public MyAgent(ChatClient.Builder builder) {
this.chatClient = builder.build();
}

@AgentCoreInvocation
public String chat(PromptRequest request) {
return chatClient.prompt()
.user(request.prompt())
.call()
.content();
}
}

record PromptRequest(String prompt) {}
```

### Step 3: Configure Amazon Bedrock

Set your model and AWS Region in application.properties:spring.ai.bedrock.aws.region=us-east-1 spring.ai.bedrock.converse.chat.options.model=global.anthropic.claude-sonnet-4-5-20250929-v1:0

### Step 4: Test locally

Start the application and send a request:

```
mvn spring-boot:run

curl -X POST http://localhost:8080/invocations \
-H "Content-Type: application/json" \
-d '{"prompt": "What is Spring AI?"}'
```

That’s a complete, AgentCore-compatible AI agent. No custom controllers, no protocol handling, no health check implementation.

### Step 5: Add streaming

To stream responses as they’re generated, change the return type to Flux<String>. The SDK automatically switches to SSE output:

```
@AgentCoreInvocation
public Flux<String> streamingChat(PromptRequest request) {
return chatClient.prompt()
.user(request.prompt())
.stream()
.content();
}
```

The SDK handles SSE framing, Content-Type headers, newline preservation, and connection lifecycle. Your code stays focused on the AI interaction.

### Step 6: Add memory to your agent

Real-world agents must remember what users said earlier in a conversation (short-term memory) and what they’ve learned over time (long-term memory). The SDK integrates with
[AgentCore Memory](https://docs.aws.amazon.com/bedrock-agentcore/latest/devguide/memory.html)
through Spring AI’s advisor pattern, interceptors that enrich prompts with context before they reach the model.

Short-term memory (STM) keeps recent messages using a sliding window. Long-term memory (LTM) persists knowledge across sessions using four strategies:

|  |  |  |
| --- | --- | --- |
| **Strategy** | **Purpose** | **Example** |
| Semantic | Factual information about users | “User works in finance” |
| User preference | Explicit settings and choices | “Metric units preferred” |
| Summary | Condensed conversation history | Session summaries for continuity |
| Episodic | Past interactions and lessons | “User had trouble with X last week” |

AgentCore consolidates these strategies asynchronously, extracting relevant information without explicit developer intervention.Add the memory dependency and enable auto-discovery. In auto-discovery mode, the SDK automatically detects available long-term memory strategies and namespaces without manual configuration:

```
agentcore.memory.memory-id=${AGENTCORE_MEMORY_ID}
agentcore.memory.long-term.auto-discovery=true
```

Then inject AgentCoreMemory and compose it into your chat client:

```
// Add to MyAgent constructor
private final AgentCoreMemory agentCoreMemory;

public MyAgent(ChatClient.Builder builder, AgentCoreMemory agentCoreMemory) {
this.agentCoreMemory = agentCoreMemory;
this.chatClient = builder.build();
}

// Update the chat method to include memory advisors
@AgentCoreInvocation
public String chat(PromptRequest request, AgentCoreContext context) {
String sessionId = context.getHeader(AgentCoreHeaders.SESSION_ID);

return chatClient.prompt()
.user(request.prompt())
.advisors(agentCoreMemory.advisors)
.advisors(a -> a.param(ChatMemory.CONVERSATION_ID, "user:" + sessionId))
.call()
.content();
}
```

The agentCoreMemory.advisors list includes both STM and all configured LTM advisors. For detailed configuration options, see the
[Memory documentation](https://github.com/spring-ai-community/spring-ai-agentcore)
.

### Step 7: Extending agents with tools

AgentCore provides specialized tools that the SDK exposes as Spring AI tool callbacks through the ToolCallbackProvider interface.

**Browser automation**
– Agents can navigate websites, extract content, take screenshots, and interact with page elements using
[AgentCore Browser](https://docs.aws.amazon.com/bedrock-agentcore/latest/devguide/browser-tool.html)
:

```
<dependency>
<groupId>org.springaicommunity</groupId>
<artifactId>spring-ai-agentcore-browser</artifactId>
</dependency>
```

**Code interpreter**
– Agents can write and run Python, JavaScript, or TypeScript in a secure sandbox using
[AgentCore Code Interpreter](https://docs.aws.amazon.com/bedrock-agentcore/latest/devguide/code-interpreter-tool.html)
. The sandbox includes numpy, pandas, and matplotlib. Generated files are captured through the artifact store.

```
<dependency>
<groupId>org.springaicommunity</groupId>
<artifactId>spring-ai-agentcore-code-interpreter</artifactId>
</dependency>
```

Both tools integrate through Spring AI’s
`ToolCallbackProvider`
interface. Here is the final MyAgent with memory, browser, and code interpreter composed together:

```
@Service
public class MyAgent {

private final ChatClient chatClient;
private final AgentCoreMemory agentCoreMemory;

public MyAgent(
ChatClient.Builder builder,
AgentCoreMemory agentCoreMemory,
@Qualifier("browserToolCallbackProvider") ToolCallbackProvider browserTools,
@Qualifier("codeInterpreterToolCallbackProvider") ToolCallbackProvider codeInterpreterTools) {
this.agentCoreMemory = agentCoreMemory;
this.chatClient = builder
.defaultToolCallbacks(browserTools, codeInterpreterTools)
.build();
}

@AgentCoreInvocation
public Flux<String> chat(PromptRequest request, AgentCoreContext context) {
String sessionId = context.getHeader(AgentCoreHeaders.SESSION_ID);

return chatClient.prompt()
.user(request.prompt())
.advisors(agentCoreMemory.advisors)
.advisors(a -> a.param(ChatMemory.CONVERSATION_ID, "user:" + sessionId))
.stream()
.content();
}
}
```

The model sees all tools equally and decides which to call based on the user’s request. While this post focuses on Amazon Bedrock to access foundation models (FMs), Spring AI supports multiple large language model (LLM) providers including OpenAI and Anthropic, so you can choose the models that fit your needs. For example, a travel and expense management agent can use the browser tool to look up flight options and the code interpreter to analyze spending patterns and generate charts, all within a single conversation:

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2026/04/13/ml-19946-image-2.png)

## Deploying your agent

The SDK supports two deployment models:

**AgentCore Runtime**
– For fully managed infrastructure, package your application as an ARM64 container, push it to
[Amazon Elastic Container Registry (Amazon ECR)](https://aws.amazon.com/ecr/)
, and create an AgentCore Runtime that references the image. The runtime handles scaling and health monitoring. The
[examples/terraform](https://github.com/spring-ai-community/spring-ai-agentcore/tree/main/examples/terraform)
directory provides infrastructure as code (IaC) with IAM and OAuth authentication options.

**Standalone**
– Use AgentCore Memory, Browser, or Code Interpreter in applications running on Amazon Elastic Kubernetes Service (Amazon EKS), Amazon Elastic Container Service (Amazon ECS), Amazon Elastic Compute Cloud (Amazon EC2), or on-premises. With this approach, teams can adopt AgentCore capabilities incrementally. For example, adding memory to an existing Spring Boot service before migrating to AgentCore Runtime later.

## Authentication and authorization

AgentCore Runtime supports two authentication methods: IAM-based SigV4 for AWS service-to-service calls and OAuth2 for user-facing applications. When your Spring AI agent is deployed to AgentCore Runtime, authentication is handled at the infrastructure layer. Your application receives the authenticated user’s identity through
`AgentCoreContext`
. Fine-grained authorization can then be implemented in your Spring application using standard Spring Security patterns with these principles. For standalone deployments, your Spring application is responsible for providing authentication and authorization using Spring Security. In this case, calls to AgentCore services (Memory, Browser, Code Interpreter) are secured using standard AWS SDK credential mechanisms.

## Connecting to MCP tools with AgentCore Gateway

Spring AI agents can access organizational tools through AgentCore Gateway, which provides Model Context Protocol (MCP) support with outbound authentication and a semantic tool registry. To use Gateway, configure your Spring AI MCP client endpoint to point to AgentCore Gateway and authenticate using either IAM SigV4 or OAuth2:

```
spring.ai.mcp.client.toolcallback.enabled=true
spring.ai.mcp.client.initialized=false
spring.ai.mcp.client.streamable-http.connections.gateway.url=${GATEWAY_URL}
```

This enables agents to discover and invoke enterprise tools while Gateway handles credential management for downstream services. For a hands-on example, see the Building Java AI agents with Spring AI and Amazon Bedrock AgentCore workshop, which demonstrates MCP integration with AgentCore Gateway.

## What’s next?

The SDK continues to evolve. Upcoming integrations will include:

* *Observability*
  – Integrate Spring AI tracing, metrics, and logging with support for Amazon CloudWatch and external observability tools such as LangFuse, Datadog, and Dynatrace using OpenTelemetry. Basic AgentCore observability is available today.
* *Evaluations*
  – Testing and quality assessment frameworks for agent responses.
* *Advanced Identity management*
  – Streamlined security context retrieval for Spring AI Agents.

## Cleaning up

If you created resources while following this post, delete them to avoid ongoing charges:

1. Delete any AgentCore Runtime agents that you created.
2. Delete container images from Amazon ECR.
3. Remove IAM roles and policies created for agent deployment.
4. If you used the Terraform examples, run terraform destroy to remove all resources.

## Conclusion

In this post, we showed you how to build production-ready AI agents in Java using the Spring AI AgentCore SDK. Starting from an annotated method, we added streaming responses, persistent memory, browser automation, and code execution—all through known Spring patterns.The SDK is an open source under the Apache 2.0 license. To get started:

* Explore the
  [Spring AI AgentCore SDK on GitHub](https://github.com/spring-ai-community/spring-ai-agentcore)
  . The repository includes example applications that you can use as starting points:
  + `simple-spring-boot-app`
    — Minimal agent with basic request handling
  + `spring-ai-sse-chat-client`
    — Streaming responses with Server-Sent Events
  + `spring-ai-memory-integration`
    — Short-term and long-term memory usage
  + `spring-ai-extended-chat-client`
    — OAuth authentication with per-user memory isolation
  + `spring-ai-browser`
    — Web browsing and screenshot capabilities
* Read the
  [Amazon AgentCore documentation](https://docs.aws.amazon.com/bedrock-agentcore/latest/devguide/what-is-agentcore.html)
  for details on Runtime, Memory, Browser, and Code Interpreter services.
* Try the
  [Amazon Bedrock console](https://console.aws.amazon.com/bedrock/)
  to enable model access and explore available foundation models.
* For a hands-on deep dive, try the
  [Building Java AI agents with Spring AI and Amazon AgentCore](https://catalog.workshops.aws/java-ai-agents)
  workshop. In about four hours, you build a complete travel and expense management assistant—progressively adding persona, memory, knowledge retrieval, web browsing, code execution, MCP tool integration and deploy it serverless to AgentCore Runtime with authentication and observability. No artificial intelligence and machine learning (AI/ML) experience is required.

We welcome your feedback and contributions. Leave a comment to share your experience or open an issue on the
[GitHub repository](https://github.com/spring-ai-community/spring-ai-agentcore)
.

---

## About the authors

### Andrei Shakirin

Andrei Shakirin is a Senior Solution Architect. He helps customers in developing cloud solutions, focusing on Agentic AI, Containers, Spring AI and Java. Andrei is contributor of Spring AI, MCP Java SDK and speaker on international developer conferences.

### James Ward

James Ward Professional software developer since 1997, with much of that time spent helping developers build software that doesn’t suck. A Typed Pure Functional Programming zealot who often compromises on his ideals to just get stuff done. Currently a Developer Advocate for AWS and AAIF Technical Committee member.

### Maximilian Schellhorn

Maximilian Schellhorn works as a Principal Solutions Architect at Amazon Web Services. Before that he worked for more than 10 years as a Software Engineer & Architect on distributed system design and monolith-to-microservice transformations. His recent work focuses on SaaS, Serverless (Java) and Agentic AI.

### Matthew Meckes

Matthew Meckes works as a Principal Containers Specialist at Amazon Web Services, helping customers build and scale their most complex workloads on Kubernetes and EKS, with a particular focus on Java, AI and Platform Engineering.

### Yuriy Bezsonov

Yuriy Bezsonov is a Senior Solutions Architect. He has progressed from a software developer to an engineering manager and Solutions Architect. Now, as a Senior Solutions Architect at AWS, he assists partners and customers in developing cloud solutions, focusing on Agentic AI, container technologies, Kubernetes, Java. Yuriy holds AWS and Kubernetes certifications, and he is a recipient of the AWS Golden Jacket.

### Muhammad Hamza Usmani

Muhammad Hamza Usmani is a Senior Generative AI GTM Solutions Architect. He works on GTM topics for Amazon Bedrock pan EMEA. He is passionate about working with customers and partners, motivated by the goal of harnessing model in context learning capabilities.