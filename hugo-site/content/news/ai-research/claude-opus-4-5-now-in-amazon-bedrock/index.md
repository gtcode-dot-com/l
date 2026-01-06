---
ai_commentary: []
ai_commentary_meta:
  content_digest: ''
  generated_at: ''
  model: ''
  prompt_version: ''
  provider: ''
category: ai-research
date: '2025-11-25T00:00:20.394978+00:00'
exported_at: '2025-11-25T00:00:23.711374+00:00'
feed: https://aws.amazon.com/blogs/machine-learning/feed
language: en
source_url: https://aws.amazon.com/blogs/machine-learning/claude-opus-4-5-now-in-amazon-bedrock
structured_data:
  about: []
  author: ''
  description: Anthropic's newest foundation model, Claude Opus 4.5, is now available
    in Amazon Bedrock, a fully managed service that offers a choice of high-performing
    foundation models from leading AI companies. In this post, I'll show you what
    makes this model different, walk through key business applications, and demonstrate
    how to use Opus 4.5's new tool use capabilities on Amazon Bedrock.
  headline: Claude Opus 4.5 now in Amazon Bedrock
  inLanguage: en
  keywords: []
  main_image: ''
  original_source: https://aws.amazon.com/blogs/machine-learning/claude-opus-4-5-now-in-amazon-bedrock
  publisher:
    logo: /favicon.ico
    name: gtcode.com
title: Claude Opus 4.5 now in Amazon Bedrock
updated_at: '2025-11-25T00:00:20.394978+00:00'
url_hash: 74b3825acfd30351f2e2e26148a1c364cc4c6f05
---

Anthropic’s newest foundation model,
[Claude Opus 4.5](https://www.anthropic.com/news/claude-opus-4-5)
, is now available in
[Amazon Bedrock](https://aws.amazon.com/bedrock/)
, a fully managed service that offers a choice of high-performing foundation models from leading AI companies. Opus 4.5 is a meaningful step forward in what AI systems can do and sets a new standard across coding, agents, computer use, and office tasks. It outperforms both Sonnet 4.5 and Opus 4.1 while providing Opus-level at one-third the cost.

In this post, I’ll show you what makes this model different, walk through key business applications, and demonstrate how to use Opus 4.5’s new tool use capabilities on Amazon Bedrock. By the end, you’ll understand how to use this model’s capabilities for production agent deployments.

## Claude Opus 4.5: What makes this model different

Opus 4.5 is Anthropic’s most advanced model offering in the Opus class, designed for developers building sophisticated AI agents that can reason, plan, and execute complex tasks with minimal oversight. It upgrades Sonnet 4.5 with better performance on existing use cases and adds new capabilities for complex workflows.

The model excels in professional software engineering, achieving 80.9% on SWE-bench Verified, helping to transform multi-day development projects into hours-long tasks. It works independently including improved multilingual coding capabilities, and enhanced behaviors like more efficient code, better test coverage, and cleaner architecture choices. For office productivity, the model handles complex projects end-to-end. It powers agents that create PowerPoint presentations, Excel spreadsheets, and Word documents with professional polish, including document redlining for contracts and NDAs. The model also produces higher quality React and HTML artifacts. It maintains consistency and accuracy—important for finance and other industries where precision matters—and maintains context across files throughout long projects.

This is Anthropic’s best vision model yet, achieving 80.7% on MMMU, for workflows that depend on complex visual interpretation and multi-step navigation—such as analyzing design mockups, processing documents with complex layouts, or automating browser-based tasks—with computer use performance improving further still.

The model introduces two key improvements for agent developers. The tool search tool lets agents work with hundreds of tools by dynamically discovering and loading only what they need instead of loading all definitions upfront—potentially saving tens of thousands of tokens and preventing schema confusion when scaling to large tool libraries. Tool use examples lets you provide sample tool calls directly in the tool definition, improving accuracy for complex schemas with nested objects or arrays.

## Business applications and use cases

Opus 4.5 excels in the following use cases:

* **Software development**
  : Build agents that write and refactor code across entire projects, manage full-stack architectures, or design agentic systems that break down high-level goals into executable steps. This generation of Claude spans the full development lifecycle: Opus 4.5 for production code and sophisticated agents (those using 10+ tools in workflows like end-to-end software engineering, cybersecurity, or financial analysis), Sonnet 4.5 for rapid iteration and scaled user experiences, Haiku 4.5 for sub-agents and free-tier products. Opus 4.5 can analyze technical documentation, plan a software implementation, write the required code, and iteratively refine it—while tracking requirements and architectural context throughout the process.
* **Enterprise operations and office tasks**
  : Manage complex projects from start to finish. Opus 4.5 uses memory to maintain context and consistency across files, alongside improvements in creating spreadsheets, slides, and documents. The model handles ongoing enterprise projects, automating manual workflows.
* **Financial analysis**
  : Work across complex information systems—regulatory filings, market reports, internal data—enabling predictive modeling and proactive compliance. The model’s consistency and accuracy make it useful for finance and other industries where precision matters.
* **Cybersecurity**
  : Bring professional-grade analysis to security workflows, correlating logs, security issue databases, and security intelligence for security event detection and automated incident response.

## Integration with Amazon Bedrock AgentCore

Amazon Bedrock provides the enterprise foundation for deploying Opus 4.5 in production. The fully managed service provides a unified API for foundation models with enterprise-grade security, compliance, and governance.

Opus 4.5 integrates with
[Amazon Bedrock AgentCore](https://aws.amazon.com/bedrock/agentcore/)
, which provides the infrastructure and primitives for building production agents. AgentCore includes persistent memory for maintaining context across sessions, Tool Gateway for converting your APIs and
[Lambda functions](https://aws.amazon.com/lambda/)
into agent-compatible tools, and built-in
[identity and access management](https://aws.amazon.com/iam/)
for secure resource access. You can deploy and monitor agents with complete session isolation, long-running workflow support (up to 8 hours), and observability features—so you can focus on building agents instead of managing infrastructure.

Amazon Bedrock AgentCore provides additional capabilities for production deployments. The Tool Gateway converts your existing APIs and Lambda functions into agent-compatible tools with minimal code—working with the model’s tool search feature to orchestrate hundreds of tools. Built-in observability through
[Amazon CloudWatch](https://aws.amazon.com/cloudwatch/)
tracks token usage, latency, and error rates across your agent workflows.

## Getting started

Access the Opus 4.5 model today through Amazon Bedrock. I’ll demonstrate the model’s tool search capability—a feature that lets agents work with hundreds of tools without loading all definitions into context upfront. First, I import the required modules and set up the Amazon Bedrock client:

```
# Import required libraries
import boto3
import json
# Create a session and Bedrock client
session = boto3.Session()
bedrock_client = session.client(
    service_name='bedrock-runtime',
    region_name='us-east-1'
```

For this example, I’ll define multiple tools with
`defer_loading`
to enable tool search. This lets the model discover and load only the tools it needs instead of loading all definitions upfront:

```
# Define tools with tool search enabled
tools = [
    # Enable tool search - allows dynamic tool discovery
    {
        "type": "tool_search_tool_regex",
        "name": "tool_search_tool_regex"
    },
    # Tools marked with defer_loading are discovered on-demand
    {
        "name": "get_weather",
        "description": "Get current weather for a location",
        "input_schema": {
            "type": "object",
            "properties": {
                "location": {"type": "string"},
                "unit": {"type": "string", "enum": ["celsius", "fahrenheit"]}
            },
            "required": ["location"]
        },
        "defer_loading": True,
        # Provide example inputs to improve accuracy for complex schemas
        "input_examples": [
            {"location": "San Francisco, CA", "unit": "fahrenheit"},
            {"location": "Tokyo, Japan", "unit": "celsius"}
        ]
    },
    {
        "name": "search_documentation",
        "description": "Search AWS documentation",
        "input_schema": {
            "type": "object",
            "properties": {
                "query": {"type": "string"},
                "service": {"type": "string"}
            },
            "required": ["query"]
        },
        "defer_loading": True,
        "input_examples": [
            {"query": "Lambda pricing", "service": "lambda"},
            {"query": "S3 bucket policies"}
        ]
    },
    {
        "name": "analyze_logs",
        "description": "Analyze application logs for errors",
        "input_schema": {
            "type": "object",
            "properties": {
                "log_file": {"type": "string"},
                "time_range": {"type": "string"}
            },
            "required": ["log_file"]
        },
        "defer_loading": True,
        "input_examples": [
            {"log_file": "/var/log/app.log", "time_range": "last 24 hours"},
            {"log_file": "/var/log/error.log"}
        ]
    }
]
```

Now I call the model using the
`invoke_model`
API with the effort parameter set to
`medium`
:

```
# Construct the request with beta features enabled
request_body = {
    "anthropic_version": "bedrock-2023-05-31",
    # Enable beta features: tool search, tool examples, and effort parameter
    "anthropic_beta": ["tool-search-tool-2025-10-19", "tool-examples-2025-10-29", "effort-2025-11-24"],
    "max_tokens": 4096,
    "temperature": 0.7,
    # Set effort to "medium" for balanced token usage
    "output_config": {
        "effort": "medium"
    },
    "messages": [
        {
            "role": "user",
            "content": "What's the weather in Seattle?"
        }
    ],
    "tools": tools
}

)
# Invoke the model
response = bedrock_client.invoke_model(
    modelId="global.anthropic.claude-opus-4-5-20251101-v1:0",
    body=json.dumps(request_body)

# Parse the response
response_body = json.loads(response['body'].read())
```

The model uses tool search to find the relevant tool (
`get_weather`
) from the library without loading all tool definitions upfront. The effort parameter, available in beta, controls how liberally the model spends tokens across thinking, tool calls, and responses. You can set effort to
`high`
for best results,
`medium`
for balanced usage, or
`low`
for conservative token usage.

## Key features for agent development

Opus 4.5 has several capabilities that make it well-suited for building production agents. The model maintains coherence across extended workflows for consistent decision-making for agents that run multi-step processes over hours or days. Better tool handling means agents interact more reliably with external systems, APIs, and software interfaces—the model chooses the right tools and interprets results more accurately. Opus 4.5 also tracks information across conversation turns and maintains context, helping agents accumulate knowledge over time and make decisions based on history.

The effort parameter, available in beta, gives you control over token usage. You can set it to
`high`
for best results when quality matters most,
`medium`
for balanced performance, or
`low`
for conservative token usage. Opus 4.5 adjusts token spending across thinking, tool calls, and responses based on this setting. For production deployments, Amazon Bedrock AgentCore provides monitoring and observability through CloudWatch integration, tracking token usage in real-time (useful when tuning the effort parameter), along with latency metrics, session duration, and error rates to help optimize agent performance and manage costs.

## Pricing

The model is priced at $5 per million input tokens and $25 per million output tokens, making Opus-level intelligence accessible at one-third the cost of previous offerings.

## Availability and access

This model is available today in Amazon Bedrock through
[cross-Region inference](https://docs.aws.amazon.com/bedrock/latest/userguide/cross-region-inference.html)
, which automatically routes requests to available capacity across AWS Regions for higher throughput during peak demand.

Use this model for agents that handle long-running tasks, coordinate multiple tools, or maintain context across extended sessions.

For detailed information about availability, pricing, and model specifications, visit the
[Amazon Bedrock documentation](https://docs.aws.amazon.com/bedrock/)
.

## Conclusion

This post showed you how to get started with Claude Opus 4.5 in Amazon Bedrock. Opus 4.5 excels at complex, long-running workflows like software development and enterprise operations. Opus 4.5’s capabilities in tool handling, context management, and decision-making make it valuable for building agents that operate reliably in production environments. The model works well for agents in software engineering, research synthesis, and enterprise workflow automation.

I encourage you to experiment with Opus 4.5 for your own agent workflows. Consider how its capabilities could improve manual processes in your organization, or support new types of automation. The combination of Opus 4.5’s capabilities with Amazon Bedrock’s enterprise features provides a foundation for production AI agents.

To get started, try the model in the
[Amazon Bedrock console](https://console.aws.amazon.com/bedrock/)
, explore the technical documentation, and check out
[Anthropic’s Claude model detail page](https://www.anthropic.com/claude)
for more information about its capabilities. To deploy agents at scale, explore Opus 4.5 in Amazon Bedrock AgentCore for managed infrastructure with tool orchestration and monitoring.

I’d love to hear about what you build with this model—share your experiences and agent use cases in the comments below!

---

### About the authors

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/01/31/ML-18234-auth3.jpg)
**[Jonathan Evans](https://www.linkedin.com/in/jonathan-evans-29b150133/)**
is a Worldwide Solutions Architect for Generative AI at AWS, where he helps customers leverage cutting-edge AI technologies with Anthropic’s Claude models on Amazon Bedrock, to solve complex business challenges. With a background in AI/ML engineering and hands-on experience supporting machine learning workflows in the cloud, Jonathan is passionate about making advanced AI accessible and impactful for organizations of all sizes.