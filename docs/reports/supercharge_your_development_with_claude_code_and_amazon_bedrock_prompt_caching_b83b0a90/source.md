[Skip to Main Content](#aws-page-content-main)

* Filter: All

* English
* [Contact us](https://aws.amazon.com/contact-us/?nc2=h_ut_cu)
* [AWS Marketplace](https://aws.amazon.com/marketplace/?nc2=h_utmp)
* Support
* My account

* Search

  Filter: All
* [Sign in to console](https://console.aws.amazon.com/console/home/?nc2=h_si&src=header-signin)
* [Create account](https://portal.aws.amazon.com/gp/aws/developer/registration/index.html?nc2=h_su&src=header_signup)

AWS Blogs

* [Home](https://aws.amazon.com/blogs/)
* Blogs
* Editions

## [Artificial Intelligence](https://aws.amazon.com/blogs/machine-learning/)

# Supercharge your development with Claude Code and Amazon Bedrock prompt caching

by Jonathan Evans, Gideon Teo, Omar Elkharbotly, and Daniel Wirjo on 04 JUN 2025 in [Amazon Bedrock](https://aws.amazon.com/blogs/machine-learning/category/artificial-intelligence/amazon-machine-learning/amazon-bedrock/ "View all posts in Amazon Bedrock"), [Artificial Intelligence](https://aws.amazon.com/blogs/machine-learning/category/artificial-intelligence/ "View all posts in Artificial Intelligence"), [Foundation models](https://aws.amazon.com/blogs/machine-learning/category/artificial-intelligence/generative-ai/foundation-models/ "View all posts in Foundation models"), [Generative AI](https://aws.amazon.com/blogs/machine-learning/category/artificial-intelligence/generative-ai/ "View all posts in Generative AI"), [Technical How-to](https://aws.amazon.com/blogs/machine-learning/category/post-types/technical-how-to/ "View all posts in Technical How-to") [Permalink](https://aws.amazon.com/blogs/machine-learning/supercharge-your-development-with-claude-code-and-amazon-bedrock-prompt-caching/)  [Comments](https://aws.amazon.com/blogs/machine-learning/supercharge-your-development-with-claude-code-and-amazon-bedrock-prompt-caching/#Comments)  Share

***September 2025: Added [Guidance for Claude Code with Amazon Bedrock](https://aws.amazon.com/solutions/guidance/claude-code-with-amazon-bedrock/) as a consideration when deploying Claude Code to your organization.***

Prompt caching in [Amazon Bedrock](https://aws.amazon.com/bedrock/) is now generally available, delivering performance and cost benefits for agentic AI applications. Coding assistants that process large codebases represent an ideal use case for prompt caching.

In this post, we’ll explore how to combine Amazon Bedrock [prompt caching](https://aws.amazon.com/bedrock/prompt-caching/) with [Claude Code](https://www.anthropic.com/claude-code)—a coding agent released by Anthropic that is now [generally available](https://www.anthropic.com/news/claude-4). This powerful combination transforms your development workflow by delivering lightning-fast responses from reducing inference response latency, as well as lowering input token costs. You’ll discover how this makes AI-assisted coding not just more efficient, but also more economically viable for everyday development tasks.

## What is Claude Code?

![Claude Code](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/05/24/6826a6227b1fbd47034d1936_claude-code.png)

Claude Code is Anthropic’s AI coding assistant powered by [Claude Sonnet 4](https://aws.amazon.com/bedrock/anthropic/). It operates directly in your terminal, your favorite [IDEs](https://docs.anthropic.com/en/docs/claude-code/ide-integrations) such as VS Code and Jetbrains, and in the background with [Claude Code SDK](https://docs.anthropic.com/en/docs/claude-code/sdk), understanding your project context and taking actions without requiring you to manually manipulate and add generated code to a project. Unlike traditional coding assistants, Claude Code can:

* Write code and fix bugs spanning multiple files across your codebase
* Answer questions about your code’s architecture and logic
* Run and fix tests, linting, and other commands
* Search through git history, resolve merge conflicts, and create commits and PRs
* Operate all of your other command line tools, like AWS CLI, Terraform, and k8s

The most compelling aspect of Claude Code is how it integrates into your existing workflow. You simply point it to your project directory and interact with it using natural language commands. Claude Code also supports [Model Context Protocol (MCP)](https://docs.anthropic.com/en/docs/agents-and-tools/mcp), allowing you to connect external tools and data sources directly to your terminal and customize its AI capabilities with your context.

To learn more, see [Claude Code tutorials](https://docs.anthropic.com/en/docs/claude-code/tutorials) and [Claude Code: Best practices for agentic coding](https://www.anthropic.com/engineering/claude-code-best-practices).

## Amazon Bedrock prompt caching for AI-assisted development

The prompt caching feature of Amazon Bedrock dramatically reduces both response times and costs when working with large context. Here’s how it works: When prompt caching is enabled, your agentic AI application (such as Claude Code) inserts cache checkpoint markers at specific points in your prompts. Amazon Bedrock then interprets these application-defined markers and creates cache checkpoints that save the entire model state after processing the preceding text. On subsequent requests, if your prompt reuses that same prefix, the model loads the cached state instead of recomputing.

In the context of Claude Code specifically, this means the application intelligently manages these cache points when processing your codebase, allowing Claude to “remember” previously analyzed code without incurring the full computational and financial cost of reprocessing it. When you ask multiple questions about the same code or iteratively refine solutions, Claude Code leverages these cache checkpoints to deliver faster responses while dramatically reducing token consumption and associated costs.

To learn more, see [documentation for Amazon Bedrock prompt caching](https://docs.aws.amazon.com/bedrock/latest/userguide/prompt-caching.html).

## Solution overview: Try Claude Code with Amazon Bedrock prompt caching

### Prerequisites

* An AWS account with access to Amazon Bedrock.
* Appropriate [AWS Identity and Access Management (IAM)](https://aws.amazon.com/iam/) roles and permissions for Amazon Bedrock.
* Amazon Bedrock [model access](https://docs.aws.amazon.com/bedrock/latest/userguide/model-access.html) to Anthropic Claude Sonnet 4 on AWS Regions where prompt caching is currently supported such as us-east-1 and us-west-2.
* [AWS command line interface (AWS CLI)](https://docs.aws.amazon.com/cli/latest/userguide/getting-started-install.html) configured with your AWS credentials.

Prompt caching is automatically turned on for [supported models and AWS Regions](https://docs.aws.amazon.com/bedrock/latest/userguide/prompt-caching.html#prompt-caching-models).

### Setting up Claude Code with Claude Sonnet 4 on Amazon Bedrock

After configuring AWS CLI with your credentials, follow these steps:

1. In your terminal, run the following commands:

   ```
   # Install Claude Code
   npm install -g @anthropic-ai/claude-code

   # Configure for Amazon Bedrock
   export CLAUDE_CODE_USE_BEDROCK=1
   export ANTHROPIC_MODEL='us.anthropic.claude-sonnet-4-20250514-v1:0'
   export ANTHROPIC_SMALL_FAST_MODEL='us.anthropic.claude-3-5-haiku-20241022-v1:0'

   # Launch Claude Code
   claude
   ```
2. Verify that Claude Code is running by checking for the **Welcome to Claude Code!** message in your terminal.

   ![Terminal - Welcome to Claude Code](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/05/24/image-24-2.png)

To learn more about how to configure Claude Code for Amazon Bedrock, see [Connect to Amazon Bedrock](https://docs.anthropic.com/en/docs/claude-code/overview#connect-to-amazon-bedrock).

### Getting started with prompt caching

To get started, let’s experiment with a simple prompt.

1. In Claude Code, run the prompt:

   ```
   build a basic text-based calculator
   ```
2. Review and respond to Claude Code’s requests:
   1. When prompted with questions like `Do you want to create calculator.py?` select `1. Yes` to continue.

      *Example question:*

      ```
      Do you want to create calculator.py?

      1. Yes
      2. Yes, and don't ask again for this session (shift+tab)
      3. No, and tell Claude what to do differently (esc)
      ```
   2. Carefully review each request before approving to maintain security.
3. After Claude Code generates the calculator application, it will display instructions such as:

   ```
   Run the calculator with: python3 calculator.py
   ```
4. Test the application by running the instructed command above. Then, follow the on-screen prompts to perform calculations.

Claude Code automatically enables prompt caching to optimize performance and costs. To monitor token usage and costs, use the `/cost` command. You will receive a detailed breakdown similar to this:

```
/cost
  ⎿  Total cost:            $0.0827
  ⎿  Total duration (API):  26.3s
  ⎿  Total duration (wall): 42.3s
  ⎿  Total code changes:    62 lines added, 0 lines removed
```

This output provides valuable insights into your session’s resource consumption, including total cost, API processing time, wall clock time, and code modifications.

### Getting started with prompt caching

To understand the benefits of prompt caching, let’s try the same prompt without prompt caching for comparison:

1. In the terminal, exit **Claude Code** by pressing `Ctrl+C`.
2. To create a new project directory, run the command:

   ```
   mkdir test-disable-prompt-caching; cd test-disable-prompt-caching
   ```
3. Disable prompt caching by setting an environment variable:

   ```
   export DISABLE_PROMPT_CACHING=1
   ```
4. Run `claude` to run Claude Code.
5. Verify prompt caching is disabled by checking the terminal output. You should see `Prompt caching: off` under the **Overrides (via env)** section.

   ![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/05/24/Claude-Code-Prompt-Caching-Off.png)
6. Run the prompt:

   ```
   build a basic text-based calculator
   ```
7. After completion, run `/cost` to view resource usage.

You will see a higher resource consumption compared to when prompt caching is enabled, even with a simple prompt:

```
/cost
  ⎿  Total cost:            $0.1029
  ⎿  Total duration (API):  32s
  ⎿  Total duration (wall): 1m 17.5s
  ⎿  Total code changes:    57 lines added, 0 lines removed
```

Without prompt caching, each interaction incurs the full cost of processing your context.

### Cleanup

To re-enable prompt caching, exit Claude Code and run unset `DISABLE_PROMPT_CACHING` before restarting Claude. Claude Code does not incur cost when you are not using it.

## Prompt caching for complex codebases and efficient iteration

When working with complex codebases, prompt caching delivers significantly greater benefits than with simple prompts. For an illustrative example, consider the initial prompt: `Develop a game similar to Pac-Man`. This initial prompt generates the foundational project structure and files. As you refine the application with prompts such as `Implement unique chase patterns for different ghosts`, the coding agent must comprehend your entire codebase to be able to make targeted changes.

Without prompt caching, you force the model to reprocess thousands of tokens representing your code structure, class relationships, and existing implementations, with each iteration.

Prompt caching alleviates this redundancy by preserving your complex context, transforming your software development workflow with:

* Dramatically reduced token costs for repeated interactions with the same files
* Faster response times as Claude Code doesn’t need to reprocess your entire codebase
* Efficient development cycles as you iterate without incurring full costs each time

## Prompt caching with Model Context Protocol (MCP)

[Model Context Protocol (MCP)](https://modelcontextprotocol.io/introduction) transforms your coding experience by connecting coding agents to your specific tools and information sources. You can connect Claude Code to [MCP servers](https://modelcontextprotocol.io/examples) that integrate to your file systems, databases, development tools and other productivity tools. This transforms a generic coding assistant into a personalized assistant that can interact with your data and tools beyond your codebase, follow your organization’s best practices, accelerating your unique development processes and workflows.

When you build on AWS, you gain additional advantages by leveraging [AWS open source MCP servers for code assistants](https://aws.amazon.com/blogs/machine-learning/introducing-aws-mcp-servers-for-code-assistants-part-1/) that provide intelligent AWS documentation search, best-practice recommendations, and real-time cost visibility, analysis and insights – without leaving your software development workflow.

Amazon Bedrock prompt caching becomes essential when working with MCP, as it preserves complex context across multiple interactions. With MCP continuously enriching your prompts with external knowledge and tools, prompt caching alleviates the need to repeatedly process this expanded context, slashing costs by up to 90% and reducing latency by up to 85%. This optimization proves particularly valuable as your MCP servers deliver increasingly sophisticated context about your unique development environment, so you can rapidly iterate through complex coding challenges while maintaining relevant context for up to 5 minutes without performance penalties or additional costs.

## Considerations when deploying Claude Code to your organization

With Claude Code now generally available, many customers are considering deployment options on AWS to take advantage of its coding capabilities. For deployments, consider your foundational architecture for security and governance:

**Consider leveraging [AWS IAM Identity Center](https://aws.amazon.com/iam/identity-center/), formerly AWS Single Sign On (SSO) to centrally govern identity and access to Claude Code.** This verifies that only authorized developers have access. Additionally, it allows developers to access resources with [temporary, role-based credentials](https://docs.aws.amazon.com/singlesignon/latest/userguide/howtogetcredentials.html), alleviating the need for static access keys and enhancing security. Prior to opening Claude Code, make sure that you configure AWS CLI to use an IAM Identity Center profile by using `aws configure sso --profile <PROFILE_NAME>`. Then, you login using the profile created `aws sso login --profile <PROFILE_NAME>`.

**Consider implementing [Guidance for Claude Code with Amazon Bedrock](https://aws.amazon.com/solutions/guidance/claude-code-with-amazon-bedrock/) for large enterprise deployments.**The guidance helps organizations deploy Claude Code, while maintaining strict control over AI resource access, seamlessly connecting to existing identity infrastructure and providing observability for developer productivity and usage patterns.

**Review [service quotas](https://docs.aws.amazon.com/bedrock/latest/userguide/quotas.html) and set an appropriate Token Per Minute (TPM) and Request Per Minute (RPM) based on the number of active developers.** Make sure that you have enough TPM and RPM quotas to support your team’s usage. For guidance, follow the [rate limit recommendations](https://docs.anthropic.com/en/docs/claude-code/costs#rate-limit-recommendations). For example, if you have 200 developers, you might request 20,000 TPM for each developer, or 4 million total TPM.

**Consider automated configuration of default environment variables.** This includes the environment variables outlined in this post, such as `CLAUDE_CODE_USE_BEDROCK`, `ANTHROPIC_MODEL`, and `ANTHROPIC_FAST_MODEL`. This will configure Claude Code to automatically connect Bedrock, providing a consistent baseline for development across teams. To begin with, organizations can start by providing developers with self-service instructions.

**Consider permissions, memory and MCP servers for your organization.** Security teams can configure managed [permissions](https://docs.anthropic.com/en/docs/claude-code/security) for what Claude Code is and is not allowed to do, which cannot be overwritten by local configuration. In addition, you can configure [memory](https://docs.anthropic.com/en/docs/claude-code/memory) across all projects which allows you to auto-add common bash commands files workflows, and style conventions to align with your organization’s preference. This can be done by deploying your `CLAUDE.md` file into an enterprise directory `/<enterprise root>/CLAUDE.md` or the user’s home directory `~/.claude/CLAUDE.md`. Finally, we recommend that one central team configures MCP servers and checks a `.mcp.json` configuration into the codebase so that all users benefit.

To learn more, contact your AWS account team or see resources:

* [Workshop: Claude Code on Amazon Bedrock](https://catalog.workshops.aws/claude-code-on-amazon-bedrock)
* [Claude Code Deployment Overview](https://docs.claude.com/en/docs/claude-code/third-party-integrations)

## Conclusion

In this post, you learned how Amazon Bedrock prompt caching can significantly enhance AI applications, with Claude Code’s agentic AI assistant serving as a powerful demonstration. By leveraging prompt caching, you can process large codebases more efficiently, helping to dramatically reduce costs and response times. With this technology you can have faster, more natural interactions with your code, allowing you to iterate rapidly with generative AI. You also learned about Model Context Protocol (MCP), and how the seamless integration of external tools lets you customize your AI assistant with specific context like documentation and web resources. Whether you’re tackling complex debugging, refactoring legacy systems, or developing new features, the combination of Amazon Bedrock’s prompt caching and AI coding agents like Claude Code offers a more responsive, cost-effective, and intelligent approach to software development.

Amazon Bedrock prompt caching is generally available with Claude 4 Sonnet and Claude 3.5 Haiku. To learn more, see [prompt caching](https://docs.aws.amazon.com/bedrock/latest/userguide/prompt-caching.html) and [Amazon Bedrock](https://aws.amazon.com/bedrock/).

Anthropic Claude Code is now generally available. To learn more, see [Claude Code overview](https://docs.anthropic.com/en/docs/claude-code/overview) and contact your AWS account team for guidance on deployment.

---

### About the Authors

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/01/31/ML-18234-auth3.jpg)**[Jonathan Evans](https://www.linkedin.com/in/jonathan-evans-29b150133/)** is a Worldwide Solutions Architect for Generative AI at AWS, where he helps customers leverage cutting-edge AI technologies with Anthropic’s Claude models on Amazon Bedrock, to solve complex business challenges. With a background in AI/ML engineering and hands-on experience supporting machine learning workflows in the cloud, Jonathan is passionate about making advanced AI accessible and impactful for organizations of all sizes.

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/02/05/wirjo.jpeg)**[Daniel Wirjo](https://www.linkedin.com/in/wirjo/)** is a Solutions Architect at AWS, focused on SaaS and AI startups. As a former startup CTO, he enjoys collaborating with founders and engineering leaders to drive growth and innovation on AWS. Outside of work, Daniel enjoys taking walks with a coffee in hand, appreciating nature, and learning new ideas.

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/02/06/omrsamer.jpg)**[Omar Elkharbotly](https://www.linkedin.com/in/omar-samer-1a0141112/)** is a Senior Cloud Support Engineer at AWS, specializing in Data, Machine Learning, and Generative AI solutions. With extensive experience in helping customers architect and optimize their cloud-based AI/ML/GenAI workloads, Omar works closely with AWS customers to solve complex technical challenges and implement best practices across the AWS AI/ML/GenAI service portfolio. He is passionate about helping organizations leverage the full potential of cloud computing to drive innovation in generative AI and machine learning.

![](https://d2908q01vomqb2.cloudfront.net/f1f836cb4ea6efb2a0b1b99f41ad8b103eff4b59/2025/05/28/gidteo.jpg)**[Gideon Teo](https://www.linkedin.com/in/gideonteozhikai/)** is a FSI Solution Architect at AWS in Melbourne, where he brings specialised expertise in Amazon SageMaker and Amazon Bedrock. With a deep passion for both traditional AI/ML methodologies and the emerging field of Generative AI, he helps financial institutions leverage cutting-edge technologies to solve complex business challenges. Outside of work, he cherishes quality time with friends and family, and continuously expands his knowledge across diverse technology domains.

Loading comments…

### Resources

* [Getting Started](https://aws.amazon.com/getting-started?sc_ichannel=ha&sc_icampaign=acq_awsblogsb&sc_icontent=machine-learning-resources)
* [What's New](https://aws.amazon.com/new?sc_ichannel=ha&sc_icampaign=acq_awsblogsb&sc_icontent=machine-learning-resources)

---

### Blog Topics

* [Amazon Bedrock](https://aws.amazon.com/blogs/machine-learning/category/artificial-intelligence/amazon-machine-learning/amazon-bedrock/)
* [Amazon Comprehend](https://aws.amazon.com/blogs/machine-learning/category/artificial-intelligence/amazon-comprehend/)
* [Amazon Kendra](https://aws.amazon.com/blogs/machine-learning/category/artificial-intelligence/amazon-kendra/)
* [Amazon Lex](https://aws.amazon.com/blogs/machine-learning/category/artificial-intelligence/amazon-lex/)
* [Amazon Polly](https://aws.amazon.com/blogs/machine-learning/category/artificial-intelligence/amazon-polly/)
* [Amazon Q](https://aws.amazon.com/blogs/machine-learning/category/amazon-q/)
* [Amazon Rekognition](https://aws.amazon.com/blogs/machine-learning/category/artificial-intelligence/amazon-rekognition/)
* [Amazon SageMaker](https://aws.amazon.com/blogs/machine-learning/category/artificial-intelligence/sagemaker/)
* [Amazon Textract](https://aws.amazon.com/blogs/machine-learning/category/artificial-intelligence/amazon-textract/)

---

### Follow

* [Twitter](https://twitter.com/awscloud)
* [Facebook](https://www.facebook.com/amazonwebservices)
* [LinkedIn](https://www.linkedin.com/company/amazon-web-services/)
* [Twitch](https://www.twitch.tv/aws)
* [Email Updates](https://pages.awscloud.com/communication-preferences?sc_ichannel=ha&sc_icampaign=acq_awsblogsb&sc_icontent=maching-learning-social)

[Create an AWS account](https://portal.aws.amazon.com/gp/aws/developer/registration/index.html?nc1=f_ct&src=footer_signup)

## Learn

* [What Is AWS?](/what-is-aws/?nc1=f_cc)
* [What Is Cloud Computing?](/what-is-cloud-computing/?nc1=f_cc)
* [What Is Agentic AI?](/what-is/agentic-ai/?nc1=f_cc)
* [Cloud Computing Concepts Hub](/what-is/?nc1=f_cc)
* [AWS Cloud Security](/security/?nc1=f_cc)
* [What's New](/new/?nc1=f_cc)
* [Blogs](/blogs/?nc1=f_cc)
* [Press Releases](https://press.aboutamazon.com/press-releases/aws)

## Resources

* [Getting Started](/getting-started/?nc1=f_cc)
* [Training](/training/?nc1=f_cc)
* [AWS Trust Center](/trust-center/?nc1=f_cc)
* [AWS Solutions Library](/solutions/?nc1=f_cc)
* [Architecture Center](/architecture/?nc1=f_cc)
* [Product and Technical FAQs](/faqs/?nc1=f_dr)
* [Analyst Reports](/resources/analyst-reports/?nc1=f_cc)
* [AWS Partners](/partners/work-with-partners/?nc1=f_dr)

## Developers

* [Builder Center](/developer/?nc1=f_dr)
* [SDKs & Tools](/developer/tools/?nc1=f_dr)
* [.NET on AWS](/developer/language/net/?nc1=f_dr)
* [Python on AWS](/developer/language/python/?nc1=f_dr)
* [Java on AWS](/developer/language/java/?nc1=f_dr)
* [PHP on AWS](/developer/language/php/?nc1=f_cc)
* [JavaScript on AWS](/developer/language/javascript/?nc1=f_dr)

## Help

* [Contact Us](/contact-us/?nc1=f_m)
* [File a Support Ticket](https://console.aws.amazon.com/support/home/?nc1=f_dr)
* [AWS re:Post](https://repost.aws/?nc1=f_dr)
* [Knowledge Center](https://repost.aws/knowledge-center/?nc1=f_dr)
* [AWS Support Overview](/premiumsupport/?nc1=f_dr)
* [Get Expert Help](https://iq.aws.amazon.com/?utm=mkt.foot/?nc1=f_m)
* [AWS Accessibility](/accessibility/?nc1=f_cc)
* [Legal](/legal/?nc1=f_cc)

English

Back to top

Amazon is an Equal Opportunity Employer: Minority / Women / Disability / Veteran / Gender Identity / Sexual Orientation / Age.

[x](https://twitter.com/awscloud) [facebook](https://www.facebook.com/amazonwebservices) [linkedin](https://www.linkedin.com/company/amazon-web-services/) [instagram](https://www.instagram.com/amazonwebservices/) [twitch](https://www.twitch.tv/aws) [youtube](https://www.youtube.com/user/AmazonWebServices/Cloud/) [podcasts](/podcasts/?nc1=f_cc) [email](https://pages.awscloud.com/communication-preferences?trk=homepage)

* [Privacy](/privacy/?nc1=f_pr)
* [Site terms](/terms/?nc1=f_pr)
* Cookie Preferences

© 2025, Amazon Web Services, Inc. or its affiliates. All rights reserved.