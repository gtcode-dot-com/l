---
ai_commentary: []
ai_commentary_meta:
  content_digest: ''
  generated_at: ''
  model: ''
  prompt_version: ''
  provider: ''
category: ai-research
date: '2025-11-18T02:20:57.986812+00:00'
exported_at: '2025-11-18T02:21:00.089636+00:00'
feed: https://aws.amazon.com/blogs/machine-learning/feed
language: en
source_url: https://aws.amazon.com/blogs/machine-learning/amazon-bedrock-agentcore-and-claude-transforming-business-with-agentic-ai
structured_data:
  about: []
  author: ''
  description: In this post, we explore how Amazon Bedrock AgentCore and Claude are
    enabling enterprises like Cox Automotive and Druva to deploy production-ready
    agentic AI systems that deliver measurable business value, with results including
    up to 63% autonomous issue resolution and 58% faster response times. We examine
    the technical foundation combining Claude's frontier AI capabilities with AgentCore's
    enterprise-grade infrastructure that allows organizations to focus on agent logic
    rather than building complex operational systems from scratch.
  headline: 'Amazon Bedrock AgentCore and Claude: Transforming business with agentic
    AI'
  inLanguage: en
  keywords: []
  main_image: ''
  original_source: https://aws.amazon.com/blogs/machine-learning/amazon-bedrock-agentcore-and-claude-transforming-business-with-agentic-ai
  publisher:
    logo: /favicon.ico
    name: gtcode.com
title: 'Amazon Bedrock AgentCore and Claude: Transforming business with agentic AI'
updated_at: '2025-11-18T02:20:57.986812+00:00'
url_hash: 4a8f2a6aff3a935bb215a8495f0eaffbc247efe3
---

The enterprise AI conversation has fundamentally shifted. We’re no longer asking “Can AI understand language?” but rather “Can AI autonomously execute complex business processes that drive real value?” According to
[McKinsey research](https://www.mckinsey.com/industries/automotive-and-assembly/our-insights/empowering-advanced-industries-with-agentic-ai)
, agentic AI has the potential to generate $450 billion to $650 billion in additional annual revenue by 2030, representing a 5 to 10 percent revenue increase across industries.

The window for competitive advantage is narrowing. While your competitors experiment with AI pilots, the organizations that move agentic AI into production are capturing measurable gains today. Yet here’s the paradox we keep seeing: enterprises build impressive prototypes that never scale. The gap isn’t in model capabilities, but rather in the operational infrastructure required to deploy agents that can work autonomously for hours, integrate securely with enterprise systems, and maintain reliability at scale. The figure below outlines the various challenges that organizations may face taking their agents to production.

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/11/17/ML-19937-1.png)

But some organizations have already crossed this divide. They’re running AI agents in production right now, handling real business processes, serving thousands of customers, and delivering results that seemed impossible just months ago. Let’s start with what they’ve achieved.

## What’s possible today: Production results from leading organizations

Cox Automotive and Druva are both putting Amazon Bedrock AgentCore and Claude to work across their organizations.

### Cox Automotive: Accelerating enterprise-scale agentic AI deployment

As the world’s largest automotive services and technology company,
[Cox Automotive](https://www.coxautoinc.com/)
has a wide breadth of products and services that touch almost all aspects of the automotive industry and a vehicle’s lifecycle. Agentic AI holds the promise to connect solutions and help consumers, dealers, automakers, and other automotive stakeholders to help execute workflows in more automated, scalable, and even personalized ways. AI agents can fundamentally transform every touchpoint in automotive, from how consumers search and purchase vehicles to how dealers manage service operations and inventory. This is happening in production right now at Cox Automotive. Cox Automotive has shifted from “Data-First, AI-Enabled” to “AI-First, Data Differentiated.” Cox Automotive is using Anthropic’s Claude model and
[Amazon Bedrock AgentCore](https://aws.amazon.com/bedrock/agentcore/)
as one of their critical capabilities for agentic AI solution deployment at scale with 17 major proofs of concept deployed in production and seven industry-transformational solutions currently in development.

> *“At Cox Automotive, we’re transforming our customer experience with generative and agentic AI. We are working with all frontier model providers but have anchored on Claude for its strong performance across three critical metrics: latency, cost, and accuracy. Amazon Bedrock AgentCore is one of the strategic tools we’re using to build AI agents that can deploy at scale, ranging from virtual assistants that improve our omnichannel dealer experience to an agentic marketplace that streamlines vehicle discovery and buying. AgentCore’s key capabilities – runtime for secured deployments, observability for monitoring, identity for authentication, and enterprise grade primitives are enabling our teams to develop and test these agents efficiently as we scale AI across the enterprise.”*
> *–*
> Marianne Johnson, EVP & Chief Product Officer, Cox Automotive

### Druva: Up to 63% autonomous resolution with up to 58% faster response times

Druva’s customers faced an escalating challenge in cybersecurity: staying ahead of evolving data anomalies across complex infrastructure. Manual threat investigation meant navigating multiple dashboards, logs, and alerts. In security, missing threat signals can lead to catastrophic consequences—but the volume of potential signals makes comprehensive manual review impossible.

Consider the scale: over 7,500 customers, each with their own infrastructure patterns, threat landscapes, and security requirements. The challenge was building an AI solution that could operate reliably and securely at this scale.

Druva partnered with the AWS Generative AI Innovation Center to build
[DruAI,](https://www.druva.com/about/press-releases/druva-introduces-ai-agents-to-simplify-cyber-resilience?sc_channel=sm&sc_publisher=LINKEDIN&sc_country=global&sc_geo=GLOBAL&sc_outcome=awareness&linkId=853661217)
a multi-agent system powered by Claude on Amazon Bedrock AgentCore. The system uses multiple AI agents that work together to automatically choose the right tools from hundreds of options, handling telemetry analysis, threat investigation, and remediation. AgentCore Runtime provides a more secure, isolated execution environment with automated scaling, allowing Druva’s team to focus on delivering customer value rather than building and maintaining complex security infrastructure.

The impact: Over 3,000 customers and 10,000 users now deploy DruAI, resulting in up to 58% faster time-to-resolution and solving up to 63% of customer issues without human intervention. In cybersecurity, speed is the difference between contained threats and business-impacting breaches.

> *“Our customers at Druva needed to transform their manual threat investigation processes, which involved navigating multiple dashboards, logs, and alerts. Using AgentCore’s Runtime, we rapidly deployed DruAI, our suite of AI capabilities for customers, with complete session isolation and automated scaling – enabling us to focus on delivering value to customers rather than building and maintaining complex security infrastructure. Our system handles telemetry analysis, threat investigation and remediation, and is already being used by over 3,000 customers and 10,000 users. DruAI delivers 58% faster time-to-resolution, solving 63% of customer issues without human intervention.”*
>
> – David Gildea, VP of Product, AI, Druva

These results raise an obvious question: How did organizations achieve production deployments that deliver measurable business value? The answer lies in combining two critical elements that work better together than either could alone.

## Why Amazon Bedrock AgentCore and Claude by Anthropic

Agentic AI in production requires two things: frontier AI capabilities that can handle complex, autonomous workflows, and enterprise-grade infrastructure that provides the security, reliability, and operational foundation those agents need to run in production. Amazon Bedrock AgentCore and Claude provide this combination. AgentCore has multiple fully-managed services that can be used together or independently as part of Amazon Bedrock AgentCore: Runtime, Memory, Identity, Gateway, Code Interpreter, Browser Tool, and Observability.

## Agent intelligence and logic: Focus on what matters

When enterprises build agentic AI, engineering teams usually spend months building infrastructure like session management, credential vaults, tool orchestration, observability frameworks, and scaling logic. By the time they’re ready to focus on the actual agent logic and business value, they’re exhausted and the use case may have evolved.Amazon Bedrock AgentCore is a comprehensive agentic platform to build, deploy and operate highly capable agents at scale. It’s model-agnostic, which means it handles the infrastructure and operational challenges so your developers can concentrate on what differentiates your business: the agent’s logic and the specific tasks it needs to perform. Claude’s high performance and contextual understanding are maximized by this approach.

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/11/17/ML-19937-2.png)

AgentCore works with frameworks your team already knows like
[Strands Agents](https://strandsagents.com/latest/)
, CrewAI, LangGraph, LlamaIndex. You can also use it with any foundation model, whether hosted on Amazon Bedrock or elsewhere. This removes the traditional tradeoff between open source flexibility and enterprise-grade reliability.

### Enterprise-grade security and reliability built in

Although optimized for agentic AI workflows, Claude alone doesn’t provide the production infrastructure that complex agents require. That’s where Amazon Bedrock AgentCore comes in. AgentCore provides complete session isolation to make sure each execution is fully contained, secure credential vaults help protect sensitive tokens, and identity-aware authorization controls exactly what agents can access. Agents can work autonomously for up to eight hours with automatic scaling, delivering the reliability that business processes demand.

### Enhanced agent capabilities

AgentCore provides built-in tools that extend what Claude-powered agents can accomplish. Code Interpreter offers secure code execution for data processing and analysis, while Browser enables agents to interact with web applications, navigate pages, extract data, and execute transactions.

But the real multiplier is
**AgentCore Gateway**
: it transforms your existing REST APIs and AWS Lambda functions into agent-ready tools with semantic routing. Your agents can interact with your existing business systems, databases, and services without rebuilding everything for AI. The gateway handles dual-sided security and intelligent tool selection, so as you scale to hundreds or thousands of tools, agents can still find and use the right ones.

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/11/17/ML-19937-3.png)

Together, these elements create something neither could achieve alone: AI agents with frontier intelligence, enterprise-grade reliability, and the operational foundation to deliver business value in production—not in six months after you build infrastructure, but now. The previous figure shows the benefits of AgentCore Gateway.

## The technology behind these results

Let’s explore the technology foundation that makes these results possible, without getting lost in implementation details.

### Infrastructure that scales production workloads

Amazon Bedrock AgentCore is purpose-built infrastructure for production agentic AI. Think of it as the operational foundation that transforms capable AI models into usable business systems. Rather than spending months on undifferentiated heavy lifting or building production ready agents from scratch, it’s available as a managed agentic platform.

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/11/17/ML-19937-4.png)

The AgentCore Runtime and AgentCore Identity services provide more secure, serverless execution where agents work autonomously for up to eight hours with complete session isolation. Identity management integrates with your existing providers—Okta, Microsoft Entra, or Amazon Cognito—handling OAuth, token management, and comprehensive audit trails that can help align with the most stringent compliance requirements, including those trusted by AWS GovCloud (US) customers. The Gateway transforms REST APIs and Lambda functions into agent-compatible tools with intelligent semantic routing, while AgentCore Memory is straightforward for developers to use to build context-aware agents by minimizing complex memory infrastructure, so that agents can maintain context across conversations and build knowledge bases over time.

Observability delivers complete visibility through CloudWatch with OpenTelemetry compatibility for systems like Dynatrace, Datadog, Arize Phoenix, LangSmith, and Langfuse. You can track what agents are doing, monitor performance, identify errors, and maintain the operational visibility that production systems demand. AgentCore services support VPC, AWS PrivateLink, CloudFormation, and resource tagging for enhanced enterprise security.

### Claude’s intelligence that handles complex, long-running tasks

While infrastructure enables deployment, model capabilities determine what agents can accomplish.
[Claude Sonnet 4.5](https://www.anthropic.com/news/claude-sonnet-4-5)
is Anthropic’s best performing model for agentic AI use cases, with capabilities specifically designed for autonomous, long-running workflows.

Claude Sonnet 4.5 can work independently for extended periods while maintaining clarity and focus. The model makes steady progress on tasks rather than attempting everything simultaneously, providing fact-based updates that accurately reflect accomplishments. This capability is critical for complex workflows that require sustained attention and incremental progress over hours.

The model tracks token usage throughout conversations and maintains awareness of its working context. This helps prevent remature task abandonment and enables more effective execution on long-running operations. Combined with memory capabilities that enable storage and retrieval of information outside the immediate context window, agents can maintain state across sessions and build knowledge bases over time.

Built with Anthropic’s Constitutional AI method, Claude is designed to be helpful, harmless, and honest. Extensive safety training has substantially reduced concerning behaviors including sycophancy, deception, and power-seeking. This alignment foundation is particularly important for enterprise deployments where agent reliability and appropriate behavior are non-negotiable requirements. When agents operate autonomously for hours, trust is fundamental.

Claude Sonnet 4.5 achieves state-of-the-art performance on coding and reasoning tasks, with enhanced planning and system design capabilities. The model excels at autonomous tasks that span hours or days while maintaining consistent performance. Beyond coding, Claude demonstrates advanced reasoning capabilities for financial analysis, research workflows, and cybersecurity applications which enable sophisticated agent applications across multiple enterprise use cases.

## Strategic implications for enterprise leaders

The decisions you make about agentic AI infrastructure are about establishing the foundation for your multi-year AI roadmap. Take these into consideration:

### System choice as competitive positioning

Your competitors are evaluating the same opportunities. The organizations that establish production agentic AI first can capture advantages that compound over time: operational efficiencies that can reduce costs while improving service, capabilities that were previously impossible becoming standard practice, and the organizational learning that comes from real-world deployment.

AI is transforming your industry. Will you be leading that transformation or reacting to it?

### Velocity of innovation: Automatic capability improvements

Claude Sonnet 4.5 was released just seven weeks after Claude Opus 4.1. That velocity of model improvement is now the baseline expectation. The system you choose determines whether you benefit from these advances automatically or face migration projects every time capabilities improve.

Organizations building on Amazon Bedrock gain access to new model capabilities as they become available without having to re-engineer, spin up migration projects, and without technical debt. Your agents become more capable over time, and your team stays focused on business value rather than system maintenance.

The expanding capabilities of AgentCore follow similar trajectories. Recent additions include enhanced Agent-to-Agent (A2A) protocol support for multi-agent coordination, expanded observability integrations, and new tools like Browser and Code Interpreter. These capabilities become available to your agents as they launch, future-proofing your investments while maintaining backward compatibility.

### The multi-agent future: Coordination and specialization

As individual agents prove value in your organization, the next frontier involves coordinated multi-agent systems where specialized agents collaborate on complex business challenges. Amazon Bedrock supports multi-agent collaboration through the A2A protocol, enabling sophisticated patterns:

**Specialized agent teams**
where you deploy focused agents, each excelling at specific domains like financial analysis, code review, customer interaction, security monitoring, working together under intelligent orchestration.

**Supervisor agents**
that break down complex workflows into manageable sub-tasks, delegate to appropriate specialist agents, and synthesize results into coherent outcomes.

Organizations like Druva are already running multi-agent systems in production, and the architectural patterns are becoming established. The infrastructure foundation you choose will determine how smoothly you can evolve to these sophisticated deployments tomorrow.

## Risk mitigation: Security, governance, and compliance

Enterprise deployments require security and governance built into the foundation. AgentCore provides complete audit trails for compliance, fine-grained authorization that scales with your agent environment, and session isolation that help contain potential issues. Constitutional AI in Claude Sonnet 4.5 helps provide an additional reliability layer: when agents operate autonomously, you need confidence they’ll behave appropriately and align with your instructions.

### Evaluating agentic AI for your enterprise

If you’re a technical leader or architect exploring agentic AI for your organization, here’s a practical framework for evaluation and adoption.

### Start with high-value use cases

The most successful early deployments share common characteristics. Look for workflows that are:

* **Repetitive yet require judgment**
  : Tasks your team does regularly that follow patterns but need decision-making, not just automation
* **Multi-system integration opportunities:**
  Processes that involve pulling data from multiple sources, making decisions, and taking actions across different systems
* **24/7 availability benefits:**
  Workflows where autonomous operation outside business hours provides real value
* **Clear, measurable success metrics:**
  Use cases where you can quantify impact—time saved, accuracy improved, costs reduced, capacity increased

What are the equivalent opportunities in your business?

## Move from evaluation to production decisively

The evaluation process should be measured in weeks, not months:

**Week 1-2:**
Review case studies and assess relevance to your context. Identify 1-2 pilot workflows with defined success criteria. Reach out to your AWS account team to discuss using Claude with Amazon Bedrock AgentCore for help assessing technical fit and business value potential.

**Week 3-4:**
Prototype with production infrastructure from day one. Leverage AgentCore so you’re not building throwaway infrastructure. Your learnings and code can transfer directly to production.

**Week 5-8:**
Run your pilot and measure against your success criteria. With production infrastructure already in place, this is about validating business value, not rebuilding for scale.

**Week 9+:**
Scale based on proven results. The AgentCore infrastructure scales automatically, so moving from pilot to production is about expanding scope, not re-engineering foundations.

This timeline is achievable because you’re not building infrastructure from scratch. Your AWS account team can connect you with resources, technical guidance, and examples from organizations like Cox Automotive and Druva who’ve already walked this path.

## Conclusion: The agentic enterprise is being built today

Agentic AI represents a fundamental shift in how enterprises put AI to work, moving from tools that assist to systems that act autonomously. The technical requirements for production deployment are substantial, but the combination of Amazon Bedrock AgentCore and Claude Sonnet 4.5 makes this transformation accessible.

The infrastructure exists. Organizations are already running agents in production with measurable business impact. The question for enterprise leaders is no longer “Is agentic AI ready?” but rather “How quickly can we capture this advantage?”

Organizations that master agentic AI are improving operational efficiency and reimagining what’s possible in their industries. The agentic enterprise of the future is being built now by teams that combine the right model capabilities with the right operational infrastructure.

Ready to explore what’s possible for your organization? Reach out to your AWS account team to get started with Claude in Amazon Bedrock AgentCore. They can help you assess use cases, design your pilot, and accelerate your path to production agentic AI.

The foundation is ready. The models are proven. The path forward is clear.

---

### About the authors

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/11/17/ML-19937-5-100x129.jpeg)
**Jawhny Cooke**
is a Senior Anthropic Specialist Solutions Architect for Generative AI at AWS. He specializes in integrating and deploying Anthropic models on AWS infrastructure. He partners with customers and AI providers to implement production-grade generative AI solutions through Amazon Bedrock, offering expert guidance on architecture design and system implementation to maximize the potential of these advanced models.

**![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/11/17/Brad-General-Assembly-Headshot-100x140.jpeg)
Brad Abrams**
is Head of Product for the Claude Developer Platform at Anthropic, where he leads API product development and works on building tools that help developers create powerful AI agents. Prior to Anthropic, Brad spent significant time at Google, where he was recognized as one of the most influential technologists in the voice assistant landscape. He also held roles at Microsoft, bringing deep expertise in developer tools and platform ecosystems. Brad holds a Bachelor of Science in Computer Science from North Carolina State University. Throughout his career, he has focused on developer experience, distributed systems, and software product management. Based in Palo Alto, he continues to drive innovation at the intersection of AI capabilities and developer tooling.