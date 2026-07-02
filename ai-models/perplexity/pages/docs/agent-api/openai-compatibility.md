---
title: "OpenAI Compatibility"
source: https://docs.perplexity.ai/docs/agent-api/openai-compatibility
path: docs/agent-api/openai-compatibility
---

Use your existing OpenAI SDKs with Perplexity's Agent API. Full compatibility with minimal code changes.

## Overview

Perplexity's Agent API is fully compatible with OpenAI's Responses API interface. You can use your existing OpenAI client libraries by simply changing the base URL and providing your Perplexity API key.

<Info>
  **Endpoint Note:** Perplexity's canonical Agent API endpoint is `POST /v1/agent`. For OpenAI SDK compatibility, `POST /v1/responses` is also accepted as an alias — the OpenAI SDK automatically routes `client.responses.create()` to `/v1/responses`, which Perplexity handles seamlessly. No SDK changes are needed beyond setting the base URL.
</Info>

<Tip>
  **We recommend using the [Perplexity SDK](/docs/sdk/overview)** for the best experience with full type safety, enhanced features, and preset support. Use OpenAI SDKs if you're already integrated and need drop-in compatibility.
</Tip>

## Quick Start

Use the OpenAI SDK with Perplexity's Agent API:

<Tabs>
  <Tab title="Python">
    ```python theme={null}
    import os
    from openai import OpenAI

    client = OpenAI(
        api_key=os.environ.get("PERPLEXITY_API_KEY"),
        base_url="https://api.perplexity.ai/v1"
    )

    response = client.responses.create(
        model="openai/gpt-5.5",
        input="Explain the key differences between REST and GraphQL APIs"
    )

    print(response.output_text)
    ```
  </Tab>

  <Tab title="Typescript">
    ```typescript theme={null}
    import OpenAI from 'openai';

    const client = new OpenAI({
      apiKey: process.env.PERPLEXITY_API_KEY,
      baseURL: "https://api.perplexity.ai/v1"
    });

    const response = await client.responses.create({
      model: "openai/gpt-5-mini",
      input: "Explain the key differences between REST and GraphQL APIs"
    });

    console.log(response.output_text);
    ```
  </Tab>
</Tabs>

<Accordion title="Response">
  ```json theme={null}
  {
    "id": "resp_7edd7725-4ae1-49ad-9e96-22c93679363e",
    "created_at": 1779391454,
    "model": "openai/gpt-5.1",
    "object": "response",
    "output": [
      {
        "results": [
          {
            "id": 1,
            "snippet": "- REST follows a resource-based architecture and typically uses multiple endpoints for different resources.\n- GraphQL provides a single endpoint where clients can request exactly the data they need.\n- GraphQL helps reduce over-fetching and under-fetching, which can occur in traditional REST APIs.\n...\nHere are some key differences between GraphQL and REST APIs based on how they handle endpoints, data fetching, and real-time communication.\n|GraphQL|REST API|\n|--|--|\n|GraphQL uses single endpoint for every operation.|REST API uses multiple endpoints for different operations|\n|In GraphQL client defines what data is required.|REST API fetches data using pre-defined rules.|\n|GraphQL reduces over-fetching and under-fetching.|Over-fetching and under-fetching are the common issues with Rest API.|\n|GraphQL supports real-time updates with subscriptions|REST API relies on polling for real-time data|\n|GraphQL is a growing technology with various tools and libraries.|REST APIs are well established ecosystem with multiple libraries and tools.|",
            "title": "GraphQL vs REST - GeeksforGeeks",
            "url": "https://www.geeksforgeeks.org/graphql/graphql-vs-rest-which-is-better-for-apis/",
            "date": "2026-03-11",
            "last_updated": "2026-05-18",
            "source": "web"
          },
          {
            "id": 2,
            "snippet": "GraphQL queries access not just the properties of one resource but also smoothly follow references between them.\nWhile typical REST APIs require loading from multiple URLs, GraphQL APIs get all the data your app needs in a single request.",
            "title": "GraphQL | The query language for modern APIs",
            "url": "https://graphql.org",
            "date": null,
            "last_updated": "2026-05-06",
            "source": "web"
          },
          {
            "id": 3,
            "snippet": "{ts:15} rest let's talk about the fundamental differences between graphql and rest rest stands for representational State\n{ts:22} transfer and it typically has unique URLs it follows the standard HTTP methods of get post put and delete it\n{ts:31} has uses status code standardization so you have the 200 okay the 404 not found Etc and data is typically returned in\n{ts:39} Json or XML format graphql stands for graph query language and it has a single endpoint for all operations you have the\n{ts:48} three primary operations of query mutation and subscription the client specifies exactly what data it needs and\n{ts:56} the API documents itself through introspection with graphql clients have precise control over the data that it\n{ts:63} requires so there's no such thing as over fetching or under fetching and these performance implications are",
            "title": "GraphQL vs REST: What's the Difference and When Should You ...",
            "url": "https://www.youtube.com/watch?v=2wz19HOyu1w",
            "date": "2025-04-01",
            "last_updated": "2026-04-14",
            "source": "web"
          },
          {
            "id": 4,
            "snippet": "- GraphQL is built around the concept of \"getting exactly what you asked for\"without any data under or overfetching.\n- GraphQL makes it easier to aggregate data from multiple sources.\nIt uses a type system rather than multiple endpoints to describe data.\n...\nWhile typical REST APIs require loading from multiple URLs, GraphQL APIs get all the data in a single request - making apps quick even on slow mobile network connections.\n...\nConversely, if you wanted to gather some information from a specific endpoint, you couldn’t limit the fields that the REST API returns; you’ll always get a complete data set - or overfetching.\n...\nHowever, the most commonly stated benefit is that GraphQL solves both over-fetching and under-fetching issues by allowing the client to request only the data that is required.\nSince there is more efficiency associated with working with GraphQL, development is much faster with GraphQL than it would be with REST.\n...\nGraphQL queries themselves are not faster than REST queries, but since you have full control over what you want to query and what the payload should be, GraphQL requests will always be smaller and more efficient.",
            "title": "What Is GraphQL and How It Works - Hygraph",
            "url": "https://hygraph.com/learn/graphql",
            "date": "2025-10-27",
            "last_updated": "2026-05-13",
            "source": "web"
          },
          {
            "id": 5,
            "snippet": "Unlike REST, which typically uses multiple endpoints to fetch data and perform network operations, GraphQL exposes data models by using a single endpoint through which clients send GraphQL requests, regardless of what they’re asking for.\nThe API then accesses resource properties—and follows the references between resources—to get the client all the data they need from a single query to the GraphQL server.\n...\nGraphQL offers an efficient, more flexible addition to REST; GraphQL APIs are often viewed as an upgrade from RESTful environments, especially given their ability to facilitate collaboration between front-end and back-end teams.\n...\nBecause REST relies on multiple endpoints and stateless interactions—where every API request is processed as a new query, independent of any others—clients receive every piece of data that is associated with a resource.\nIf a client needs only a subset of the data, it still receives all the data (over-fetching).\nAnd if the client needs data that spans multiple resources, a RESTful system often makes the client query each resource separately to compensate for inadequate data retrieval from the initial request (under-fetching).\nGraphQL APIs use a single GraphQL endpoint to give clients a precise, comprehensive data response in a one round trip from a single request, eliminating over- and under-fetching issues.\n...\nGraphQL reduces the need for versioning because clients can specify their data requirements in the query.\nThe addition of new fields to the server does not affect clients without a need for those fields.\n...\nREST doesn’t have built-in support for real-time updates.\nIf an app needs real-time functionality, developers usually must implement techniques like long-polling (where the client repeatedly polls the server for new data) and server-sent events, which can add complexity to the application.\nHowever, GraphQL includes built-in support for real-time updates through subscriptions.",
            "title": "GraphQL vs REST: What's the Difference? - IBM",
            "url": "https://www.ibm.com/think/topics/graphql-vs-rest-api",
            "date": "2024-03-29",
            "last_updated": "2026-01-17",
            "source": "web"
          },
          {
            "id": 6,
            "snippet": "As stated in REST API vs GraphQL, “the key difference between GraphQL and REST APIs is that GraphQL is a query language, while REST is an architectural concept for network-based software.”",
            "title": "The Role and Impact of GraphQL - F5 Networks",
            "url": "https://www.f5.com/resources/reports/the-role-and-impact-of-graphql-octo-report",
            "date": null,
            "last_updated": "2026-05-21",
            "source": "web"
          },
          {
            "id": 7,
            "snippet": "The key differences lie in data fetching, schema definition, versioning, and error handling.\nGraphQL uses a single endpoint and allows clients to specify their data requirements, while REST relies on multiple endpoints with fixed data structures.",
            "title": "GraphQL vs REST: Key Similarities and Differences Explained",
            "url": "https://konghq.com/blog/learning-center/graphql-vs-rest",
            "date": "2025-02-28",
            "last_updated": "2026-05-19",
            "source": "web"
          },
          {
            "id": 8,
            "snippet": "Instead of exposing multiple endpoints that return fixed response structures, a GraphQL API typically exposes a **single endpoint**.\nClients send queries that specify exactly what data they need.\n...\nWhile REST and GraphQL ultimately solve the same problem—exposing data through an API—their design philosophies differ in several important ways.\n|Aspect|REST|GraphQL|\n|--|--|--|\n|API structure|Multiple endpoints representing resources|Typically a single endpoint|\n|Data retrieval|Server defines response structure|Client specifies required fields|\n|Network requests|Often multiple requests for related data|Complex data fetched in a single query|\n|Versioning|Often uses versioned endpoints|Uses schema evolution and field deprecation|\n|Caching|Strong support via HTTP caching|Typically handled at the client level|",
            "title": "REST vs GraphQL: Key Differences, Performance, and When to Use ...",
            "url": "https://dev.to/riteshkokam/rest-vs-graphql-key-differences-performance-and-when-to-use-each-51n7",
            "date": "2026-03-09",
            "last_updated": "2026-05-21",
            "source": "web"
          },
          {
            "id": 9,
            "snippet": "Unlike REST, GraphQL allows for requesting specific data that a client needs, departing from the fixed data structure approach.\n...\nIn a nutshell, mainly the progress GraphQL has made is querying in one request, while retrieving only the necessary data instead of the complete set.\nThe main reason for GraphQL being so attractive to developers is its client-driven approach.\n...\nHowever, notable differences start with the conceptual models: While REST is made up of files, GraphQL is constructed of graphs.",
            "title": "GraphQL: Core Features, Architecture, Pros and Cons - AltexSoft",
            "url": "https://www.altexsoft.com/blog/graphql-core-features-architecture-pros-and-cons/",
            "date": "2019-03-23",
            "last_updated": "2026-03-31",
            "source": "web"
          }
        ],
        "type": "search_results",
        "queries": [
          "REST vs GraphQL key differences",
          "REST API characteristics",
          "GraphQL API characteristics"
        ]
      },
      {
        "id": "msg_d44758f0-ae0f-4d8a-8ded-ceb68d67ab49",
        "content": [
          {
            "text": "REST and GraphQL are both ways to build APIs, but REST is an architectural style built around multiple resource URLs and HTTP semantics, while GraphQL is a query language over a single endpoint where the client specifies exactly which data it needs.[web:5][web:6] GraphQL typically reduces over‑fetching and under‑fetching compared to REST by letting clients shape responses, at the cost of more complexity in schema design and caching.[web:1][web:8]\n\n## Core conceptual difference\n\n- REST is an **architectural** pattern that exposes resources via multiple endpoints, using HTTP verbs (GET, POST, PUT, DELETE, etc.) and status codes to model operations.[web:1][web:5]  \n- GraphQL is a **query** language and runtime that sits behind usually one endpoint and lets clients send structured queries, mutations, and subscriptions against a typed schema.[web:2][web:4][web:6]\n\n## Endpoints and data fetching\n\n- REST typically has many endpoints (e.g., `/users`, `/users/1/posts`) and each endpoint returns a fixed data shape defined by the server.[web:1][web:7]  \n- GraphQL usually has a single endpoint (e.g., `/graphql`), and the client declares exactly which fields and related objects it wants in a single request, often avoiding multiple round trips.[web:2][web:4][web:5]\n\n## Over‑fetching, under‑fetching, and performance\n\n- With REST, clients often receive more data than needed (over‑fetching) or must call several endpoints to collect enough data (under‑fetching), especially for nested relationships.[web:1][web:5][web:9]  \n- GraphQL queries return only requested fields, which reduces payload sizes and the number of requests, though raw query speed is not inherently faster; efficiency comes from tailoring the payload.[web:4][web:8]\n\n## Typing, versioning, and evolution\n\n- REST responses are often JSON without a strict, machine‑enforced schema, and breaking changes are commonly managed with versioned URLs like `/api/v1` and `/api/v2`.[web:5][web:8]  \n- GraphQL uses a strongly typed schema with introspection, enabling tools, self‑documentation, and schema evolution via adding fields and deprecating old ones instead of creating new API versions.[web:2][web:4][web:5][web:8]\n\n## Caching and real‑time features\n\n- REST works naturally with HTTP caching (ETags, Cache‑Control) because resources are tied to URLs and standard methods, making it straightforward for browsers and proxies to cache responses.[web:5][web:8]  \n- GraphQL usually needs custom or client‑side caching strategies (e.g., normalized caches) due to a single endpoint, but it offers built‑in support for real‑time updates via subscriptions, whereas REST relies on techniques like polling or server‑sent events.[web:1][web:4][web:5]",
            "type": "output_text",
            "annotations": [],
            "logprobs": []
          }
        ],
        "role": "assistant",
        "status": "completed",
        "type": "message"
      }
    ],
    "status": "completed",
    "error": null,
    "usage": {
      "input_tokens": 5870,
      "output_tokens": 679,
      "total_tokens": 6549,
      "cost": {
        "currency": "USD",
        "input_cost": 0.00286,
        "output_cost": 0.00679,
        "total_cost": 0.0151,
        "cache_creation_cost": null,
        "cache_read_cost": 0.00045,
        "tool_calls_cost": 0.005
      },
      "input_tokens_details": {
        "cache_creation_input_tokens": 0,
        "cache_read_input_tokens": 3584,
        "cached_tokens": 3584
      },
      "tool_calls_details": {
        "search_web": {
          "invocation": 1
        }
      },
      "output_tokens_details": {
        "reasoning_tokens": 0
      }
    },
    "background": false,
    "completed_at": 1779391454,
    "frequency_penalty": 0,
    "incomplete_details": null,
    "instructions": "## Abstract\n<role>\nYou are an AI assistant developed by Perplexity AI. Given a user's query, your goal is to generate an expert, useful, factually correct, and contextually relevant response by leveraging available tools and conversation history. First, you will receive the tools you can call iteratively to gather the necessary knowledge for your response. You need to use these tools rather than using internal knowledge. Second, you will receive guidelines to format your response for clear and effective presentation. Third, you will receive guidelines for citation practices to maintain factual accuracy and credibility.\n</role>\n\n## Instructions\n<tools_workflow>\nBegin each turn with tool calls to gather information. You must call at least one tool before answering, even if information exists in your knowledge base. Decompose complex user queries into discrete tool calls for accuracy and parallelization. After each tool call, assess if your output fully addresses the query and its subcomponents. Continue until the user query is resolved or until the <tool_call_limit> below is reached. End your turn with a comprehensive response. Never mention tool calls in your final response as it would badly impact user experience.\n\n<tool_call_limit> Make at most three tool calls before concluding.</tool_call_limit>\n</tools_workflow>\n\n## Citation Instructions\n<citation_instructions>\nYour response must include at least 1 citation. Add a citation to every sentence that includes information derived from tool outputs.\nTool results are provided using `id` in the format `type:index`. `type` is the data source or context. `index` is the unique identifier per citation.\n<common_source_types> are included below.\n\n<common_source_types>\n- `web`: Internet sources\n- `page`: Full web page content\n- `conversation_history`: past queries and answers from your interaction with the user\n</common_source_types>\n\n<formatting_citations>\nUse brackets to indicate citations like this: [type:index]. Commas, dashes, or alternate formats are not valid citation formats. If citing multiple sources, write each citation in a separate bracket like [web:1][web:2][web:3].\n\nCorrect: \"The Eiffel Tower is in Paris [web:3].\"\nIncorrect: \"The Eiffel Tower is in Paris [web-3].\"\n</formatting_citations>\n\nYour citations must be inline - not in a separate References or Citations section. Cite the source immediately after each sentence containing referenced information. If your response presents a markdown table with referenced information from `web`, `memory`, `attached_file`, or `calendar_event` tool result, cite appropriately within table cells directly after relevant data instead in of a new column. Do not cite `generated_image` or `generated_video` inside table cells.\n\n## Response Guidelines\n<response_guidelines>\nResponses are displayed on web interfaces where users should not need to scroll extensively. Limit responses to 5 sections maximum. Users can ask follow-up questions if they need additional detail. Prioritize the most relevant information for the initial query.\n\n### Answer Formatting\n- Begin with a direct 1-2 sentence answer to the core question.\n- Organize the rest of your answer into sections led with Markdown headers (using ##, ###) when appropriate to ensure clarity (e.g. entity definitions, biographies, and wikis).\n- Your answer should be at least 3 sentences long.\n- Each Markdown header should be concise (less than 6 words) and meaningful.\n- Markdown headers should be plain text, not numbered.\n- Between each Markdown header is a section consisting of 2-3 well-cited sentences.\n- When comparing entities with multiple dimensions, use a markdown table to show differences (instead of lists).\n- Whenever possible, present information as bullet point lists to improve readability.\n- You are allowed to bold at most one word (**example**) per paragraph. You can't bold consecutive words.\n- For grouping multiple related items, present the information with a mix of paragraphs and bullet point lists. Do not nest lists within other lists.\n\n### Tone\n<tone>\nExplain clearly using plain language. Use active voice and vary sentence structure to sound natural. Ensure smooth transitions between sentences. Avoid personal pronouns like \"I\". Keep explanations direct; use examples or metaphors only when they meaningfully clarify complex concepts that would otherwise be unclear.\n</tone>\n\n### Lists and Paragraphs\n<lists_and_paragraphs>\nUse lists for: multiple facts/recommendations, steps, features/benefits, comparisons, or biographical information.\n\nAvoid repeating content in both intro paragraphs and list items. Keep intros minimal. Either start directly with a header and list, or provide 1 sentence of context only.\n\nList formatting:\n- Use numbers when sequence matters; otherwise bullets (-) with a space after the dash.\n- Use numbers when sequence matters; otherwise bullets (-).\n- No whitespace before bullets (i.e. no indenting), one item per line.\n- Sentence capitalization; periods only for complete sentences.\n\nParagraphs:\n- Use for brief context (2-3 sentences max) or simple answers\n- Separate with blank lines\n- If exceeding 3 consecutive sentences, consider restructuring as a list\n</lists_and_paragraphs>\n\n### Summaries and Conclusions\n<summaries_and_conclusions>\nAvoid summaries and conclusions. They are not needed and are repetitive. Markdown tables are not for summaries. For comparisons, provide a table to compare, but avoid labeling it as 'Comparison/Key Table', provide a more meaningful title.\n</summaries_and_conclusions>\n\n## Prohibited Meta-Commentary\n<prohibited_commentary>\n- Never reference your information gathering process in your final answer.\n- Do not use phrases such as:\n- \"Based on my search results...\"\n- \"Now I have gathered comprehensive information...\"\n- \"According to my research...\"\n- \"My search revealed...\"\n- \"I found information about...\"\n- \"Let me provide a detailed answer...\"\n- \"Let me compile this information...\"\n- \"Short Answer: ...\"\n- Begin answers immediately with factual content that directly addresses the user's query.\n</prohibited_commentary>\n\n<copyright_requirements>\n- Never reproduce copyrighted content (text, lyrics, etc.)\n- You may share public domain content (expired copyrights, traditional works)\n- When copyright status is uncertain, treat as copyrighted\n- Keep summaries brief (under 30 words) and original — don't reconstruct sources\n- Brief factual statements (names, dates, facts) are always acceptable\n</copyright_requirements>\n\nCurrent date: Thursday, May 21, 2026\n\n",
    "max_output_tokens": 8192,
    "max_tool_calls": null,
    "metadata": {},
    "parallel_tool_calls": true,
    "presence_penalty": 0,
    "previous_response_id": null,
    "prompt_cache_key": null,
    "reasoning": null,
    "safety_identifier": null,
    "service_tier": "default",
    "store": true,
    "temperature": 1,
    "text": {
      "format": {
        "type": "text"
      }
    },
    "tool_choice": "auto",
    "tools": [
      {
        "type": "web_search"
      },
      {
        "type": "fetch_url"
      }
    ],
    "top_logprobs": 0,
    "top_p": 1,
    "truncation": "disabled",
    "user": null
  }
  ```
</Accordion>

## Configuration

### Setting Up the OpenAI SDK

Configure OpenAI SDKs to work with Perplexity by setting the `base_url` to `https://api.perplexity.ai/v1`:

<Tabs>
  <Tab title="Python">
    ```python theme={null}
    import os
    from openai import OpenAI

    client = OpenAI(
        api_key=os.environ.get("PERPLEXITY_API_KEY"),
        base_url="https://api.perplexity.ai/v1"
    )
    ```
  </Tab>

  <Tab title="Typescript">
    ```typescript theme={null}
    import OpenAI from 'openai';

    const client = new OpenAI({
      apiKey: process.env.PERPLEXITY_API_KEY,
      baseURL: "https://api.perplexity.ai/v1"
    });
    ```
  </Tab>
</Tabs>

<Info>
  **Important**: Use `base_url="https://api.perplexity.ai/v1"` (with `/v1`) for the Agent API.
</Info>

## Agent API

Perplexity's Agent API follows OpenAI's Responses API request/response format. The OpenAI SDK's `client.responses.create()` method works out of the box — the SDK sends requests to `/v1/responses`, which Perplexity accepts alongside the canonical `/v1/agent` endpoint.

### Basic Usage

<Tabs>
  <Tab title="Python">
    ```python theme={null}
    import os
    from openai import OpenAI

    client = OpenAI(
        api_key=os.environ.get("PERPLEXITY_API_KEY"),
        base_url="https://api.perplexity.ai/v1"
    )

    response = client.responses.create(
        model="openai/gpt-5.5",
        input="Explain the key differences between REST and GraphQL APIs"
    )

    print(response.output_text)
    print(f"Response ID: {response.id}")
    ```
  </Tab>

  <Tab title="Typescript">
    ```typescript theme={null}
    import OpenAI from 'openai';

    const client = new OpenAI({
      apiKey: process.env.PERPLEXITY_API_KEY,
      baseURL: "https://api.perplexity.ai/v1"
    });

    const response = await client.responses.create({
      model: "openai/gpt-5-mini",
      input: "Explain the key differences between REST and GraphQL APIs"
    });

    console.log(response.output_text);
    console.log(`Response ID: ${response.id}`);
    ```
  </Tab>
</Tabs>

<Accordion title="Response">
  ```json theme={null}
  {
    "id": "resp_7edd7725-4ae1-49ad-9e96-22c93679363e",
    "created_at": 1779391454,
    "model": "openai/gpt-5.1",
    "object": "response",
    "output": [
      {
        "results": [
          {
            "id": 1,
            "snippet": "- REST follows a resource-based architecture and typically uses multiple endpoints for different resources.\n- GraphQL provides a single endpoint where clients can request exactly the data they need.\n- GraphQL helps reduce over-fetching and under-fetching, which can occur in traditional REST APIs.\n...\nHere are some key differences between GraphQL and REST APIs based on how they handle endpoints, data fetching, and real-time communication.\n|GraphQL|REST API|\n|--|--|\n|GraphQL uses single endpoint for every operation.|REST API uses multiple endpoints for different operations|\n|In GraphQL client defines what data is required.|REST API fetches data using pre-defined rules.|\n|GraphQL reduces over-fetching and under-fetching.|Over-fetching and under-fetching are the common issues with Rest API.|\n|GraphQL supports real-time updates with subscriptions|REST API relies on polling for real-time data|\n|GraphQL is a growing technology with various tools and libraries.|REST APIs are well established ecosystem with multiple libraries and tools.|",
            "title": "GraphQL vs REST - GeeksforGeeks",
            "url": "https://www.geeksforgeeks.org/graphql/graphql-vs-rest-which-is-better-for-apis/",
            "date": "2026-03-11",
            "last_updated": "2026-05-18",
            "source": "web"
          },
          {
            "id": 2,
            "snippet": "GraphQL queries access not just the properties of one resource but also smoothly follow references between them.\nWhile typical REST APIs require loading from multiple URLs, GraphQL APIs get all the data your app needs in a single request.",
            "title": "GraphQL | The query language for modern APIs",
            "url": "https://graphql.org",
            "date": null,
            "last_updated": "2026-05-06",
            "source": "web"
          },
          {
            "id": 3,
            "snippet": "{ts:15} rest let's talk about the fundamental differences between graphql and rest rest stands for representational State\n{ts:22} transfer and it typically has unique URLs it follows the standard HTTP methods of get post put and delete it\n{ts:31} has uses status code standardization so you have the 200 okay the 404 not found Etc and data is typically returned in\n{ts:39} Json or XML format graphql stands for graph query language and it has a single endpoint for all operations you have the\n{ts:48} three primary operations of query mutation and subscription the client specifies exactly what data it needs and\n{ts:56} the API documents itself through introspection with graphql clients have precise control over the data that it\n{ts:63} requires so there's no such thing as over fetching or under fetching and these performance implications are",
            "title": "GraphQL vs REST: What's the Difference and When Should You ...",
            "url": "https://www.youtube.com/watch?v=2wz19HOyu1w",
            "date": "2025-04-01",
            "last_updated": "2026-04-14",
            "source": "web"
          },
          {
            "id": 4,
            "snippet": "- GraphQL is built around the concept of \"getting exactly what you asked for\"without any data under or overfetching.\n- GraphQL makes it easier to aggregate data from multiple sources.\nIt uses a type system rather than multiple endpoints to describe data.\n...\nWhile typical REST APIs require loading from multiple URLs, GraphQL APIs get all the data in a single request - making apps quick even on slow mobile network connections.\n...\nConversely, if you wanted to gather some information from a specific endpoint, you couldn’t limit the fields that the REST API returns; you’ll always get a complete data set - or overfetching.\n...\nHowever, the most commonly stated benefit is that GraphQL solves both over-fetching and under-fetching issues by allowing the client to request only the data that is required.\nSince there is more efficiency associated with working with GraphQL, development is much faster with GraphQL than it would be with REST.\n...\nGraphQL queries themselves are not faster than REST queries, but since you have full control over what you want to query and what the payload should be, GraphQL requests will always be smaller and more efficient.",
            "title": "What Is GraphQL and How It Works - Hygraph",
            "url": "https://hygraph.com/learn/graphql",
            "date": "2025-10-27",
            "last_updated": "2026-05-13",
            "source": "web"
          },
          {
            "id": 5,
            "snippet": "Unlike REST, which typically uses multiple endpoints to fetch data and perform network operations, GraphQL exposes data models by using a single endpoint through which clients send GraphQL requests, regardless of what they’re asking for.\nThe API then accesses resource properties—and follows the references between resources—to get the client all the data they need from a single query to the GraphQL server.\n...\nGraphQL offers an efficient, more flexible addition to REST; GraphQL APIs are often viewed as an upgrade from RESTful environments, especially given their ability to facilitate collaboration between front-end and back-end teams.\n...\nBecause REST relies on multiple endpoints and stateless interactions—where every API request is processed as a new query, independent of any others—clients receive every piece of data that is associated with a resource.\nIf a client needs only a subset of the data, it still receives all the data (over-fetching).\nAnd if the client needs data that spans multiple resources, a RESTful system often makes the client query each resource separately to compensate for inadequate data retrieval from the initial request (under-fetching).\nGraphQL APIs use a single GraphQL endpoint to give clients a precise, comprehensive data response in a one round trip from a single request, eliminating over- and under-fetching issues.\n...\nGraphQL reduces the need for versioning because clients can specify their data requirements in the query.\nThe addition of new fields to the server does not affect clients without a need for those fields.\n...\nREST doesn’t have built-in support for real-time updates.\nIf an app needs real-time functionality, developers usually must implement techniques like long-polling (where the client repeatedly polls the server for new data) and server-sent events, which can add complexity to the application.\nHowever, GraphQL includes built-in support for real-time updates through subscriptions.",
            "title": "GraphQL vs REST: What's the Difference? - IBM",
            "url": "https://www.ibm.com/think/topics/graphql-vs-rest-api",
            "date": "2024-03-29",
            "last_updated": "2026-01-17",
            "source": "web"
          },
          {
            "id": 6,
            "snippet": "As stated in REST API vs GraphQL, “the key difference between GraphQL and REST APIs is that GraphQL is a query language, while REST is an architectural concept for network-based software.”",
            "title": "The Role and Impact of GraphQL - F5 Networks",
            "url": "https://www.f5.com/resources/reports/the-role-and-impact-of-graphql-octo-report",
            "date": null,
            "last_updated": "2026-05-21",
            "source": "web"
          },
          {
            "id": 7,
            "snippet": "The key differences lie in data fetching, schema definition, versioning, and error handling.\nGraphQL uses a single endpoint and allows clients to specify their data requirements, while REST relies on multiple endpoints with fixed data structures.",
            "title": "GraphQL vs REST: Key Similarities and Differences Explained",
            "url": "https://konghq.com/blog/learning-center/graphql-vs-rest",
            "date": "2025-02-28",
            "last_updated": "2026-05-19",
            "source": "web"
          },
          {
            "id": 8,
            "snippet": "Instead of exposing multiple endpoints that return fixed response structures, a GraphQL API typically exposes a **single endpoint**.\nClients send queries that specify exactly what data they need.\n...\nWhile REST and GraphQL ultimately solve the same problem—exposing data through an API—their design philosophies differ in several important ways.\n|Aspect|REST|GraphQL|\n|--|--|--|\n|API structure|Multiple endpoints representing resources|Typically a single endpoint|\n|Data retrieval|Server defines response structure|Client specifies required fields|\n|Network requests|Often multiple requests for related data|Complex data fetched in a single query|\n|Versioning|Often uses versioned endpoints|Uses schema evolution and field deprecation|\n|Caching|Strong support via HTTP caching|Typically handled at the client level|",
            "title": "REST vs GraphQL: Key Differences, Performance, and When to Use ...",
            "url": "https://dev.to/riteshkokam/rest-vs-graphql-key-differences-performance-and-when-to-use-each-51n7",
            "date": "2026-03-09",
            "last_updated": "2026-05-21",
            "source": "web"
          },
          {
            "id": 9,
            "snippet": "Unlike REST, GraphQL allows for requesting specific data that a client needs, departing from the fixed data structure approach.\n...\nIn a nutshell, mainly the progress GraphQL has made is querying in one request, while retrieving only the necessary data instead of the complete set.\nThe main reason for GraphQL being so attractive to developers is its client-driven approach.\n...\nHowever, notable differences start with the conceptual models: While REST is made up of files, GraphQL is constructed of graphs.",
            "title": "GraphQL: Core Features, Architecture, Pros and Cons - AltexSoft",
            "url": "https://www.altexsoft.com/blog/graphql-core-features-architecture-pros-and-cons/",
            "date": "2019-03-23",
            "last_updated": "2026-03-31",
            "source": "web"
          }
        ],
        "type": "search_results",
        "queries": [
          "REST vs GraphQL key differences",
          "REST API characteristics",
          "GraphQL API characteristics"
        ]
      },
      {
        "id": "msg_d44758f0-ae0f-4d8a-8ded-ceb68d67ab49",
        "content": [
          {
            "text": "REST and GraphQL are both ways to build APIs, but REST is an architectural style built around multiple resource URLs and HTTP semantics, while GraphQL is a query language over a single endpoint where the client specifies exactly which data it needs.[web:5][web:6] GraphQL typically reduces over‑fetching and under‑fetching compared to REST by letting clients shape responses, at the cost of more complexity in schema design and caching.[web:1][web:8]\n\n## Core conceptual difference\n\n- REST is an **architectural** pattern that exposes resources via multiple endpoints, using HTTP verbs (GET, POST, PUT, DELETE, etc.) and status codes to model operations.[web:1][web:5]  \n- GraphQL is a **query** language and runtime that sits behind usually one endpoint and lets clients send structured queries, mutations, and subscriptions against a typed schema.[web:2][web:4][web:6]\n\n## Endpoints and data fetching\n\n- REST typically has many endpoints (e.g., `/users`, `/users/1/posts`) and each endpoint returns a fixed data shape defined by the server.[web:1][web:7]  \n- GraphQL usually has a single endpoint (e.g., `/graphql`), and the client declares exactly which fields and related objects it wants in a single request, often avoiding multiple round trips.[web:2][web:4][web:5]\n\n## Over‑fetching, under‑fetching, and performance\n\n- With REST, clients often receive more data than needed (over‑fetching) or must call several endpoints to collect enough data (under‑fetching), especially for nested relationships.[web:1][web:5][web:9]  \n- GraphQL queries return only requested fields, which reduces payload sizes and the number of requests, though raw query speed is not inherently faster; efficiency comes from tailoring the payload.[web:4][web:8]\n\n## Typing, versioning, and evolution\n\n- REST responses are often JSON without a strict, machine‑enforced schema, and breaking changes are commonly managed with versioned URLs like `/api/v1` and `/api/v2`.[web:5][web:8]  \n- GraphQL uses a strongly typed schema with introspection, enabling tools, self‑documentation, and schema evolution via adding fields and deprecating old ones instead of creating new API versions.[web:2][web:4][web:5][web:8]\n\n## Caching and real‑time features\n\n- REST works naturally with HTTP caching (ETags, Cache‑Control) because resources are tied to URLs and standard methods, making it straightforward for browsers and proxies to cache responses.[web:5][web:8]  \n- GraphQL usually needs custom or client‑side caching strategies (e.g., normalized caches) due to a single endpoint, but it offers built‑in support for real‑time updates via subscriptions, whereas REST relies on techniques like polling or server‑sent events.[web:1][web:4][web:5]",
            "type": "output_text",
            "annotations": [],
            "logprobs": []
          }
        ],
        "role": "assistant",
        "status": "completed",
        "type": "message"
      }
    ],
    "status": "completed",
    "error": null,
    "usage": {
      "input_tokens": 5870,
      "output_tokens": 679,
      "total_tokens": 6549,
      "cost": {
        "currency": "USD",
        "input_cost": 0.00286,
        "output_cost": 0.00679,
        "total_cost": 0.0151,
        "cache_creation_cost": null,
        "cache_read_cost": 0.00045,
        "tool_calls_cost": 0.005
      },
      "input_tokens_details": {
        "cache_creation_input_tokens": 0,
        "cache_read_input_tokens": 3584,
        "cached_tokens": 3584
      },
      "tool_calls_details": {
        "search_web": {
          "invocation": 1
        }
      },
      "output_tokens_details": {
        "reasoning_tokens": 0
      }
    },
    "background": false,
    "completed_at": 1779391454,
    "frequency_penalty": 0,
    "incomplete_details": null,
    "instructions": "## Abstract\n<role>\nYou are an AI assistant developed by Perplexity AI. Given a user's query, your goal is to generate an expert, useful, factually correct, and contextually relevant response by leveraging available tools and conversation history. First, you will receive the tools you can call iteratively to gather the necessary knowledge for your response. You need to use these tools rather than using internal knowledge. Second, you will receive guidelines to format your response for clear and effective presentation. Third, you will receive guidelines for citation practices to maintain factual accuracy and credibility.\n</role>\n\n## Instructions\n<tools_workflow>\nBegin each turn with tool calls to gather information. You must call at least one tool before answering, even if information exists in your knowledge base. Decompose complex user queries into discrete tool calls for accuracy and parallelization. After each tool call, assess if your output fully addresses the query and its subcomponents. Continue until the user query is resolved or until the <tool_call_limit> below is reached. End your turn with a comprehensive response. Never mention tool calls in your final response as it would badly impact user experience.\n\n<tool_call_limit> Make at most three tool calls before concluding.</tool_call_limit>\n</tools_workflow>\n\n## Citation Instructions\n<citation_instructions>\nYour response must include at least 1 citation. Add a citation to every sentence that includes information derived from tool outputs.\nTool results are provided using `id` in the format `type:index`. `type` is the data source or context. `index` is the unique identifier per citation.\n<common_source_types> are included below.\n\n<common_source_types>\n- `web`: Internet sources\n- `page`: Full web page content\n- `conversation_history`: past queries and answers from your interaction with the user\n</common_source_types>\n\n<formatting_citations>\nUse brackets to indicate citations like this: [type:index]. Commas, dashes, or alternate formats are not valid citation formats. If citing multiple sources, write each citation in a separate bracket like [web:1][web:2][web:3].\n\nCorrect: \"The Eiffel Tower is in Paris [web:3].\"\nIncorrect: \"The Eiffel Tower is in Paris [web-3].\"\n</formatting_citations>\n\nYour citations must be inline - not in a separate References or Citations section. Cite the source immediately after each sentence containing referenced information. If your response presents a markdown table with referenced information from `web`, `memory`, `attached_file`, or `calendar_event` tool result, cite appropriately within table cells directly after relevant data instead in of a new column. Do not cite `generated_image` or `generated_video` inside table cells.\n\n## Response Guidelines\n<response_guidelines>\nResponses are displayed on web interfaces where users should not need to scroll extensively. Limit responses to 5 sections maximum. Users can ask follow-up questions if they need additional detail. Prioritize the most relevant information for the initial query.\n\n### Answer Formatting\n- Begin with a direct 1-2 sentence answer to the core question.\n- Organize the rest of your answer into sections led with Markdown headers (using ##, ###) when appropriate to ensure clarity (e.g. entity definitions, biographies, and wikis).\n- Your answer should be at least 3 sentences long.\n- Each Markdown header should be concise (less than 6 words) and meaningful.\n- Markdown headers should be plain text, not numbered.\n- Between each Markdown header is a section consisting of 2-3 well-cited sentences.\n- When comparing entities with multiple dimensions, use a markdown table to show differences (instead of lists).\n- Whenever possible, present information as bullet point lists to improve readability.\n- You are allowed to bold at most one word (**example**) per paragraph. You can't bold consecutive words.\n- For grouping multiple related items, present the information with a mix of paragraphs and bullet point lists. Do not nest lists within other lists.\n\n### Tone\n<tone>\nExplain clearly using plain language. Use active voice and vary sentence structure to sound natural. Ensure smooth transitions between sentences. Avoid personal pronouns like \"I\". Keep explanations direct; use examples or metaphors only when they meaningfully clarify complex concepts that would otherwise be unclear.\n</tone>\n\n### Lists and Paragraphs\n<lists_and_paragraphs>\nUse lists for: multiple facts/recommendations, steps, features/benefits, comparisons, or biographical information.\n\nAvoid repeating content in both intro paragraphs and list items. Keep intros minimal. Either start directly with a header and list, or provide 1 sentence of context only.\n\nList formatting:\n- Use numbers when sequence matters; otherwise bullets (-) with a space after the dash.\n- Use numbers when sequence matters; otherwise bullets (-).\n- No whitespace before bullets (i.e. no indenting), one item per line.\n- Sentence capitalization; periods only for complete sentences.\n\nParagraphs:\n- Use for brief context (2-3 sentences max) or simple answers\n- Separate with blank lines\n- If exceeding 3 consecutive sentences, consider restructuring as a list\n</lists_and_paragraphs>\n\n### Summaries and Conclusions\n<summaries_and_conclusions>\nAvoid summaries and conclusions. They are not needed and are repetitive. Markdown tables are not for summaries. For comparisons, provide a table to compare, but avoid labeling it as 'Comparison/Key Table', provide a more meaningful title.\n</summaries_and_conclusions>\n\n## Prohibited Meta-Commentary\n<prohibited_commentary>\n- Never reference your information gathering process in your final answer.\n- Do not use phrases such as:\n- \"Based on my search results...\"\n- \"Now I have gathered comprehensive information...\"\n- \"According to my research...\"\n- \"My search revealed...\"\n- \"I found information about...\"\n- \"Let me provide a detailed answer...\"\n- \"Let me compile this information...\"\n- \"Short Answer: ...\"\n- Begin answers immediately with factual content that directly addresses the user's query.\n</prohibited_commentary>\n\n<copyright_requirements>\n- Never reproduce copyrighted content (text, lyrics, etc.)\n- You may share public domain content (expired copyrights, traditional works)\n- When copyright status is uncertain, treat as copyrighted\n- Keep summaries brief (under 30 words) and original — don't reconstruct sources\n- Brief factual statements (names, dates, facts) are always acceptable\n</copyright_requirements>\n\nCurrent date: Thursday, May 21, 2026\n\n",
    "max_output_tokens": 8192,
    "max_tool_calls": null,
    "metadata": {},
    "parallel_tool_calls": true,
    "presence_penalty": 0,
    "previous_response_id": null,
    "prompt_cache_key": null,
    "reasoning": null,
    "safety_identifier": null,
    "service_tier": "default",
    "store": true,
    "temperature": 1,
    "text": {
      "format": {
        "type": "text"
      }
    },
    "tool_choice": "auto",
    "tools": [
      {
        "type": "web_search"
      },
      {
        "type": "fetch_url"
      }
    ],
    "top_logprobs": 0,
    "top_p": 1,
    "truncation": "disabled",
    "user": null
  }
  ```
</Accordion>

### Using Presets

Presets are pre-configured setups optimized for specific use cases. Use `extra_body` to pass presets via the OpenAI SDK:

<Tabs>
  <Tab title="Python">
    ```python theme={null}
    import os
    from openai import OpenAI

    client = OpenAI(
        api_key=os.environ.get("PERPLEXITY_API_KEY"),
        base_url="https://api.perplexity.ai/v1"
    )

    # Pass preset via extra_body
    response = client.responses.create(
        input="Compare the design philosophy of Apple's A-series and Qualcomm's Snapdragon mobile SoCs at a high level: CPU and GPU choices and overall system integration.",
        extra_body={
            "preset": "pro-search"
        }
    )

    print(response.output_text)
    ```
  </Tab>

  <Tab title="Typescript">
    ```typescript theme={null}
    import OpenAI from 'openai';

    const client = new OpenAI({
      apiKey: process.env.PERPLEXITY_API_KEY,
      baseURL: "https://api.perplexity.ai/v1"
    });

    // Use type casting (as any) to pass preset directly
    const response = await (client.responses.create as any)({
      input: "Compare the design philosophy of Apple's A-series and Qualcomm's Snapdragon mobile SoCs at a high level: CPU and GPU choices and overall system integration.",
      preset: "pro-search"
    });

    console.log(response.output_text);
    ```
  </Tab>
</Tabs>

<Accordion title="Response">
  ```json theme={null}
  {
    "id": "resp_18215035-0ac4-4b27-915c-62399ff87fc0",
    "created_at": 1779391825,
    "model": "openai/gpt-5.1",
    "object": "response",
    "output": [
      {
        "results": [
          {
            "id": 1,
            "snippet": "The *A* series is a family of SoCs used in the iPhone, certain iPad models (including iPad Mini and entry-level iPad), MacBook Neo, and the Apple TV.\n*A*-series chips were also used in the discontinued iPod Touch line and the original HomePod.\nThey integrate one or more ARM-based processing cores (CPU), a graphics processing unit (GPU), cache memory and other electronics necessary to provide mobile computing functions within a single physical package.\n...\nIt combines an ARM Cortex-A8 CPU – also used in Samsung's S5PC110A01 SoC – and a PowerVR SGX 535 graphics processor (GPU), all built on Samsung's 45-nanometer silicon chip fabrication process.\nThe design emphasizes power efficiency.",
            "title": "Apple silicon - Wikipedia",
            "url": "https://en.wikipedia.org/wiki/Apple_silicon",
            "date": "2011-07-06",
            "last_updated": "2026-05-18",
            "source": "web"
          },
          {
            "id": 2,
            "snippet": "{ts:230} Apple's range then we'll go back again to ccom so we're looking now at the M3 family it's a series of arm-based system\n{ts:237} on a chips designed by Apple the M3 process include a central processing unit and a graphics processing GPU and\n{ts:243} they are used in Apple's iMac desktops and its uh MacBook range of laptops and there are a few iPads as well which got\n…\n...\n{ts:467} Core Design needs to be certified and must be 100% compatible with the arm instruction set architecture now apple\n...\n{ts:635} years and now we have this new competitor which is kcomm now the other thing to remember about the M3 and the\n{ts:640} Snapdragon X Elite is that they are systems on a chip they are not just a CPU so maybe if you buy an x86 uh\n{ts:648} processor of some kind you're getting basically just a a CPU but now these things have a GPU for example and the M\n{ts:657} series uses Apple's uh own design GPU with its Heritage coming from imagination Technologies and this latest\n{ts:665} installation includes mesh shaders and Hardware accelerated uh ra tracing again see my previous V videos about those\n{ts:672} things and the Snapdragon X Elite uses corcom adreno GPU which supports direct X12 so here we can see that these gpus\n…\n{ts:703} course both have npus and this of course is something that's becoming very important the ability to be able to run\n{ts:711} uh these uh neural processing units generative AI uh and other kind of stuff on the so so these chips are more than\n{ts:718} just a CPU you've got GPU you've got uh edit encoders and decoders you've got npus all built into the same chip and\n…",
            "title": "Apple M3 vs Snapdragon X Elite - History, Features, and Software",
            "url": "https://www.youtube.com/watch?v=V8Rbjwz0dVU",
            "date": "2023-11-03",
            "last_updated": "2026-05-16",
            "source": "web"
          },
          {
            "id": 3,
            "snippet": "Leveraging a unified memory architecture for CPU and GPU tasks, Mac apps will see amazing performance benefits from Apple silicon tuned frameworks such as Metal and Accelerate.\n...\nNow, the new Apple Silicon Macs combine all these components into a single system on a chip, or SoC.\nBuilding everything into one chip gives the system a unified memory architecture.\nThis means that the GPU and CPU are working over the same memory.\nGraphics resources, such as textures, images and geometry data, can be shared between the CPU and GPU efficiently, with no overhead, as there's no need to copy data across a PCIe bus.",
            "title": "Explore the new system architecture of Apple silicon Macs - WWDC20",
            "url": "https://developer.apple.com/videos/play/wwdc2020/10686/",
            "date": "2020-06-24",
            "last_updated": "2026-05-14",
            "source": "web"
          },
          {
            "id": 4,
            "snippet": "Apple designs its chips specifically for iOS, which allows tight hardware and software integration.\n...\nWe also discuss how Apple Bionic processors focus on high single-core performance, efficient power management, and unified memory architecture, while Snapdragon chips focus heavily on GPU performance through Adreno graphics, higher refresh rate support, and features built for gaming phones.\n...\n{ts:330} Apple के पास ये है कि वो अपने कस्टम सीपीू आर्किटेक्चर बनाता है। ये एआरएम के कोर्स को डायरेक्टली यूज नहीं करते हैं।",
            "title": "Apple Bionic vs Snapdragon – Which Chip Is Actually Better for ...",
            "url": "https://www.youtube.com/watch?v=jiDCtvI_MC4",
            "date": "2026-03-06",
            "last_updated": "2026-05-21",
            "source": "web"
          },
          {
            "id": 5,
            "snippet": "Key Concepts\n- RISC Architecture: Utilizes a simplified instruction set for efficient processing.\n- Pipeline Organization: Enables simultaneous instruction execution for enhanced throughput.\n- Cache Hierarchy: Reduces memory access latency, improving application performance.\n- Multicore Architecture: Integrates various processing units for optimized workload management.\n- Power Optimization: Implements strategies like dynamic voltage scaling to enhance energy efficiency.\n- System on Chip (SoC): Combines CPU, GPU, and other components for seamless data exchange.\n...\nThese processors power iPhones\nand iPads and are built as a System-on-Chip (SoC), integrating the CPU, GPU, Neural Engine, and\nhardware accelerators on a single die.\n...\nApple A-Series processors are based on the ARM (Advanced RISC Machine) architecture, which\nfollows the Reduced Instruction Set Computing (RISC) philosophy.\nRISC uses a small, highly optimized\nset of simple instructions that can each execute in a single clock cycle.\n...\n##### Apple A-Series processors use a deep out-of-order superscalar pipeline.\nThis means the processor can\n...\n##### The Apple A-Series is a complete System-on-Chip.\nAll major processing blocks — CPU, GPU, Neural\n##### Engine, ISP, and media codecs — share a unified memory fabric and the System Level Cache,\n##### enabling low-latency, high-bandwidth data exchange without costly off-chip transfers.",
            "title": "CASE STUDY 3: Apple A-Series Mobile Processor Architecture",
            "url": "https://www.studocu.com/in/document/navjeevan-education-societys-polytechnic-bhandup/computer-graphics/case-study-3-apple-a-series-mobile-processor-architecture/157859088",
            "date": "2026-04-02",
            "last_updated": "2026-04-12",
            "source": "web"
          },
          {
            "id": 6,
            "snippet": "\n6-core GPU (graphics \nprocessor unit)  \n\n2 dual-core CPU \n(central processing\n...\nA13 consists of: \n\nEight-core Neural \nEngine  with\nMachine Learning \n\nFour-core GPU \n(20% faster > A12) \n\nSix-core CPU (20% \nfaster and 35% save \nenergy > A12) \n",
            "title": "Recent Advances and Outlook for Heterogeneous Integration",
            "url": "https://ewh.ieee.org/soc/cpmt/presentations/eps2002a.pdf",
            "date": null,
            "last_updated": "2025-10-23",
            "source": "web"
          },
          {
            "id": 7,
            "snippet": "In contrast, Apple designs its chips—like the A17 Pro and upcoming A18—for vertical integration within iOS.\nThis means the CPU, GPU, memory controller, and Neural Engine are all developed in-house and tightly coupled with the operating system.\nApple’s six-core CPU (two performance, four efficiency) and five-core GPU are built using TSMC’s most advanced node at the time of release, often giving them a process advantage over competing SoCs.\n...\nApple’s unified memory architecture reduces latency between CPU, GPU, and RAM, lowering energy consumption per operation.\n...\nApple’s A17 Pro and future chips generally offer superior sustained performance, better thermal management, and tighter software integration, resulting in smoother gameplay over time.",
            "title": "Snapdragon Vs Apple Chip Which Powers Smoother ...",
            "url": "https://www.alibaba.com/product-insights/snapdragon-vs-apple-chip-which-powers-smoother-mobile-gaming-performance.html",
            "date": "2026-01-08",
            "last_updated": "2026-01-16",
            "source": "web"
          },
          {
            "id": 8,
            "snippet": "A series SoCsThe A series is a family of SoCs used in the iPhone, certain iPad models (including iPad Mini and entry-level iPad), and the Apple TV.\nA-series chips were alsoused in the discontinued iPod Touch line and the original HomePod.\nThey integrate one or more ARM-based processing cores (CPU), a graphics processingunit (GPU), cache memory and other electronics necessary to provide mobile computing functions within a single physical package.[4]",
            "title": "Apple Silicon - Wikipedia | PDF | I Pad",
            "url": "https://www.scribd.com/document/909655498/Apple-Silicon-Wikipedia",
            "date": "2025-09-29",
            "last_updated": "2026-01-19",
            "source": "web"
          },
          {
            "id": 9,
            "snippet": "Snapdragon processors integrate multiple components like the CPU, GPU, NPU, and modem on a single chip.\nThis integration and specific software integrations improves processing efficiency, improves power management, reduces package size and, overall, improves overall performance of the device.\n...\nSnapdragon processors integrate multiple components like the CPU, GPU, NPU, and modem on a single chip.\nThis integration is called heterogenous computing and it improves processing efficiency, improves power management, reduces package size and, overall, improves overall performance of the device.",
            "title": "What is Snapdragon FAQ | Qualcomm",
            "url": "https://www.qualcomm.com/snapdragon/what-is-snapdragon",
            "date": "2024-06-27",
            "last_updated": "2026-05-21",
            "source": "web"
          },
          {
            "id": 10,
            "snippet": "The Apple A15 Bionic is a System on a Chip (SoC) from Apple that is found in the iPhone 13 and iPad Mini (2021) models.\nIt was announced late 2021 and offers 6 cores divided in 2 performance cores and four power efficiency cores.\nThe CPU performance increases only slightly compared to the A14, but GPU (in the higher end models) offers higher gains.\n...\nThe chip also includes a new GPU that is advertised as 50% faster, the M12 Motion co-processor and a Neural Engine with 8 cores for up to 5 trillion operations per second.",
            "title": "Qualcomm Snapdragon 8 Gen 1 vs Apple A15 Bionic ...",
            "url": "https://www.notebookcheck.net/SD-8-Gen-1-vs-A15-vs-A12-Bionic_14029_13825_10166.247596.0.html",
            "date": "2023-07-01",
            "last_updated": "2025-12-01",
            "source": "web"
          }
        ],
        "type": "search_results",
        "queries": [
          "Apple A-series SoC design philosophy CPU GPU integration",
          "Qualcomm Snapdragon design philosophy CPU GPU integration",
          "Apple A-series vs Snapdragon CPU GPU architecture high level"
        ]
      },
      {
        "id": "msg_6d730289-196f-44c5-9561-11554263bcda",
        "content": [
          {
            "text": "Apple’s A‑series SoCs are vertically optimized, custom CPU/GPU designs built for iOS with tight hardware–software co‑design and aggressive single‑thread efficiency, while Snapdragon SoCs emphasize modularity, semi‑custom ARM CPU cores, Adreno GPUs, and broad OEM feature flexibility, especially around connectivity and gaming. [web:1][web:4][web:7][web:9] At a high level, Apple optimizes one tightly controlled platform end‑to‑end, whereas Qualcomm optimizes a scalable platform that can be configured across many devices, vendors, and price tiers. [web:4][web:7][web:9]\n\n## CPU philosophy\n\n- Apple A‑series uses fully custom ARM‑compatible cores (e.g., “large” performance + “small” efficiency cores) designed in‑house rather than off‑the‑shelf Cortex designs, with a focus on high IPC and strong single‑core performance at mobile power envelopes. [web:4][web:5][web:7]  \n- Snapdragon flagships typically use ARM’s Cortex performance/efficiency cores or semi‑custom derivatives in a big.LITTLE or tri‑cluster layout, tuned for good multi‑core throughput, thermals, and time‑to‑market across many OEMs. [web:9][web:10]  \n- Because Apple controls the OS and app stack, A‑series CPU microarchitecture, cache hierarchy, and power management are co‑designed with iOS and major frameworks, allowing very aggressive per‑core performance without sacrificing battery life. [web:3][web:4][web:5][web:7]  \n- Qualcomm instead exposes a flexible platform: CPU scheduling, DVFS behavior, and thermal limits are co‑tuned with each OEM’s Android skin, form factor, and cooling solution. [web:9]  \n\n## GPU and graphics focus\n\n- Apple integrates its own in‑house GPU designs in recent A‑series generations (heritage from PowerVR, but now branded Apple GPU), tightly tied to Metal and Apple’s graphics stack. [web:1][web:3][web:4][web:7]  \n- Qualcomm’s Snapdragon line uses Adreno GPUs, a long‑running, internally developed GPU family heavily optimized for mobile gaming, high refresh displays, and broad API support (Vulkan, OpenGL ES, often desktop‑style DirectX in PC‑class parts). [web:2][web:4][web:9]  \n- Apple’s design leans toward consistent, thermally stable performance and efficient use of a unified memory architecture, which benefits real‑world rendering and GPU–CPU data sharing even when peak theoretical throughput is not always highest on paper. [web:3][web:5][web:7]  \n- Snapdragon’s philosophy has often highlighted headline GPU features for OEMs (high FPS gaming modes, variable rate shading, advanced display pipelines) to differentiate Android flagships, gaming phones, and XR devices. [web:4][web:7][web:9]  \n\n## System integration and memory\n\n- A‑series chips are classic “all‑in‑one” SoCs: CPU, GPU, Neural Engine, ISP, media codecs, secure enclave, and other accelerators share a high‑bandwidth internal fabric and system‑level cache, reducing off‑chip traffic and latency. [web:1][web:3][web:5][web:6]  \n- Apple strongly emphasizes a **unified** memory architecture and system‑level cache: CPU, GPU, and ML engines access the same physical memory pool without copies, which simplifies software and boosts efficiency for mixed workloads (e.g., compute + graphics + ML in one frame). [web:3][web:5][web:7]  \n- Snapdragon SoCs also integrate CPU, Adreno GPU, Hexagon NPU/DSP, ISP, and media engines, but place special strategic weight on heterogeneous computing: offloading pieces of a workload to the “best” block (CPU, GPU, DSP, NPU) depending on power and latency. [web:9]  \n- Unlike Apple, Qualcomm must support many OS variants and OEM stacks, so its integration strategy stresses standard interfaces and flexible partitioning rather than deep co‑design with a single OS and set of first‑party apps. [web:4][web:7][web:9]  \n\n## Connectivity and platform strategy\n\n- Apple typically pairs A‑series SoCs with separate modems (historically Qualcomm, now sometimes in‑house efforts), prioritizing SoC area and power budget for application‑processor blocks and deferring RF/telecom differentiation to the modem. [web:1][web:7]  \n- Snapdragon flagships usually integrate the cellular modem platform tightly with the SoC family (even when packaged separately), and Qualcomm positions Snapdragon as a full connectivity + compute stack: 5G, Wi‑Fi, BT, GNSS, audio codecs, and camera pipelines are part of the platform story for OEMs. [web:9]  \n- Apple’s vertical model optimizes for a small number of premium devices with long support lifetimes, using the A‑series as a cornerstone of the overall iOS experience. [web:1][web:4][web:7]  \n- Qualcomm’s model optimizes for breadth: multiple Snapdragon tiers, re‑usable IP blocks, and scalable feature sets across phones, tablets, wearables, XR headsets, PCs, and automotive, all built on related CPU/GPU/NPU architectures. [web:2][web:9]",
            "type": "output_text",
            "annotations": [],
            "logprobs": []
          }
        ],
        "role": "assistant",
        "status": "completed",
        "type": "message"
      }
    ],
    "status": "completed",
    "error": null,
    "usage": {
      "input_tokens": 6325,
      "output_tokens": 1210,
      "total_tokens": 7535,
      "cost": {
        "currency": "USD",
        "input_cost": 0.00343,
        "output_cost": 0.0121,
        "total_cost": 0.02098,
        "cache_creation_cost": null,
        "cache_read_cost": 0.00045,
        "tool_calls_cost": 0.005
      },
      "input_tokens_details": {
        "cache_creation_input_tokens": 0,
        "cache_read_input_tokens": 3584,
        "cached_tokens": 3584
      },
      "tool_calls_details": {
        "search_web": {
          "invocation": 1
        }
      },
      "output_tokens_details": {
        "reasoning_tokens": 0
      }
    },
    "background": false,
    "completed_at": 1779391825,
    "frequency_penalty": 0,
    "incomplete_details": null,
    "instructions": "## Abstract\n<role>\nYou are an AI assistant developed by Perplexity AI. Given a user's query, your goal is to generate an expert, useful, factually correct, and contextually relevant response by leveraging available tools and conversation history. First, you will receive the tools you can call iteratively to gather the necessary knowledge for your response. You need to use these tools rather than using internal knowledge. Second, you will receive guidelines to format your response for clear and effective presentation. Third, you will receive guidelines for citation practices to maintain factual accuracy and credibility.\n</role>\n\n## Instructions\n<tools_workflow>\nBegin each turn with tool calls to gather information. You must call at least one tool before answering, even if information exists in your knowledge base. Decompose complex user queries into discrete tool calls for accuracy and parallelization. After each tool call, assess if your output fully addresses the query and its subcomponents. Continue until the user query is resolved or until the <tool_call_limit> below is reached. End your turn with a comprehensive response. Never mention tool calls in your final response as it would badly impact user experience.\n\n<tool_call_limit> Make at most three tool calls before concluding.</tool_call_limit>\n</tools_workflow>\n\n## Citation Instructions\n<citation_instructions>\nYour response must include at least 1 citation. Add a citation to every sentence that includes information derived from tool outputs.\nTool results are provided using `id` in the format `type:index`. `type` is the data source or context. `index` is the unique identifier per citation.\n<common_source_types> are included below.\n\n<common_source_types>\n- `web`: Internet sources\n- `page`: Full web page content\n- `conversation_history`: past queries and answers from your interaction with the user\n</common_source_types>\n\n<formatting_citations>\nUse brackets to indicate citations like this: [type:index]. Commas, dashes, or alternate formats are not valid citation formats. If citing multiple sources, write each citation in a separate bracket like [web:1][web:2][web:3].\n\nCorrect: \"The Eiffel Tower is in Paris [web:3].\"\nIncorrect: \"The Eiffel Tower is in Paris [web-3].\"\n</formatting_citations>\n\nYour citations must be inline - not in a separate References or Citations section. Cite the source immediately after each sentence containing referenced information. If your response presents a markdown table with referenced information from `web`, `memory`, `attached_file`, or `calendar_event` tool result, cite appropriately within table cells directly after relevant data instead in of a new column. Do not cite `generated_image` or `generated_video` inside table cells.\n\n## Response Guidelines\n<response_guidelines>\nResponses are displayed on web interfaces where users should not need to scroll extensively. Limit responses to 5 sections maximum. Users can ask follow-up questions if they need additional detail. Prioritize the most relevant information for the initial query.\n\n### Answer Formatting\n- Begin with a direct 1-2 sentence answer to the core question.\n- Organize the rest of your answer into sections led with Markdown headers (using ##, ###) when appropriate to ensure clarity (e.g. entity definitions, biographies, and wikis).\n- Your answer should be at least 3 sentences long.\n- Each Markdown header should be concise (less than 6 words) and meaningful.\n- Markdown headers should be plain text, not numbered.\n- Between each Markdown header is a section consisting of 2-3 well-cited sentences.\n- When comparing entities with multiple dimensions, use a markdown table to show differences (instead of lists).\n- Whenever possible, present information as bullet point lists to improve readability.\n- You are allowed to bold at most one word (**example**) per paragraph. You can't bold consecutive words.\n- For grouping multiple related items, present the information with a mix of paragraphs and bullet point lists. Do not nest lists within other lists.\n\n### Tone\n<tone>\nExplain clearly using plain language. Use active voice and vary sentence structure to sound natural. Ensure smooth transitions between sentences. Avoid personal pronouns like \"I\". Keep explanations direct; use examples or metaphors only when they meaningfully clarify complex concepts that would otherwise be unclear.\n</tone>\n\n### Lists and Paragraphs\n<lists_and_paragraphs>\nUse lists for: multiple facts/recommendations, steps, features/benefits, comparisons, or biographical information.\n\nAvoid repeating content in both intro paragraphs and list items. Keep intros minimal. Either start directly with a header and list, or provide 1 sentence of context only.\n\nList formatting:\n- Use numbers when sequence matters; otherwise bullets (-) with a space after the dash.\n- Use numbers when sequence matters; otherwise bullets (-).\n- No whitespace before bullets (i.e. no indenting), one item per line.\n- Sentence capitalization; periods only for complete sentences.\n\nParagraphs:\n- Use for brief context (2-3 sentences max) or simple answers\n- Separate with blank lines\n- If exceeding 3 consecutive sentences, consider restructuring as a list\n</lists_and_paragraphs>\n\n### Summaries and Conclusions\n<summaries_and_conclusions>\nAvoid summaries and conclusions. They are not needed and are repetitive. Markdown tables are not for summaries. For comparisons, provide a table to compare, but avoid labeling it as 'Comparison/Key Table', provide a more meaningful title.\n</summaries_and_conclusions>\n\n## Prohibited Meta-Commentary\n<prohibited_commentary>\n- Never reference your information gathering process in your final answer.\n- Do not use phrases such as:\n- \"Based on my search results...\"\n- \"Now I have gathered comprehensive information...\"\n- \"According to my research...\"\n- \"My search revealed...\"\n- \"I found information about...\"\n- \"Let me provide a detailed answer...\"\n- \"Let me compile this information...\"\n- \"Short Answer: ...\"\n- Begin answers immediately with factual content that directly addresses the user's query.\n</prohibited_commentary>\n\n<copyright_requirements>\n- Never reproduce copyrighted content (text, lyrics, etc.)\n- You may share public domain content (expired copyrights, traditional works)\n- When copyright status is uncertain, treat as copyrighted\n- Keep summaries brief (under 30 words) and original — don't reconstruct sources\n- Brief factual statements (names, dates, facts) are always acceptable\n</copyright_requirements>\n\nCurrent date: Thursday, May 21, 2026\n\n",
    "max_output_tokens": 8192,
    "max_tool_calls": null,
    "metadata": {},
    "parallel_tool_calls": true,
    "presence_penalty": 0,
    "previous_response_id": null,
    "prompt_cache_key": null,
    "reasoning": null,
    "safety_identifier": null,
    "service_tier": "default",
    "store": true,
    "temperature": 1,
    "text": {
      "format": {
        "type": "text"
      }
    },
    "tool_choice": "auto",
    "tools": [
      {
        "type": "web_search"
      },
      {
        "type": "fetch_url"
      }
    ],
    "top_logprobs": 0,
    "top_p": 1,
    "truncation": "disabled",
    "user": null
  }
  ```
</Accordion>

<Info>
  See [Agent API Presets](/docs/agent-api/presets) for available presets and their configurations.
</Info>

### Using Third-Party Models

You can also specify third-party models directly instead of using presets:

<Tabs>
  <Tab title="Python">
    ```python theme={null}
    import os
    from openai import OpenAI

    client = OpenAI(
        api_key=os.environ.get("PERPLEXITY_API_KEY"),
        base_url="https://api.perplexity.ai/v1"
    )

    response = client.responses.create(
        model="openai/gpt-5.5",
        input="Explain the key differences between REST and GraphQL APIs"
    )

    print(response.output_text)
    ```
  </Tab>

  <Tab title="Typescript">
    ```typescript theme={null}
    import OpenAI from 'openai';

    const client = new OpenAI({
      apiKey: process.env.PERPLEXITY_API_KEY,
      baseURL: "https://api.perplexity.ai/v1"
    });

    const response = await client.responses.create({
      model: "openai/gpt-5-mini",
      input: "Explain the key differences between REST and GraphQL APIs"
    });

    console.log(response.output_text);
    ```
  </Tab>
</Tabs>

<Accordion title="Response">
  ```json theme={null}
  {
    "id": "resp_7edd7725-4ae1-49ad-9e96-22c93679363e",
    "created_at": 1779391454,
    "model": "openai/gpt-5.1",
    "object": "response",
    "output": [
      {
        "results": [
          {
            "id": 1,
            "snippet": "- REST follows a resource-based architecture and typically uses multiple endpoints for different resources.\n- GraphQL provides a single endpoint where clients can request exactly the data they need.\n- GraphQL helps reduce over-fetching and under-fetching, which can occur in traditional REST APIs.\n...\nHere are some key differences between GraphQL and REST APIs based on how they handle endpoints, data fetching, and real-time communication.\n|GraphQL|REST API|\n|--|--|\n|GraphQL uses single endpoint for every operation.|REST API uses multiple endpoints for different operations|\n|In GraphQL client defines what data is required.|REST API fetches data using pre-defined rules.|\n|GraphQL reduces over-fetching and under-fetching.|Over-fetching and under-fetching are the common issues with Rest API.|\n|GraphQL supports real-time updates with subscriptions|REST API relies on polling for real-time data|\n|GraphQL is a growing technology with various tools and libraries.|REST APIs are well established ecosystem with multiple libraries and tools.|",
            "title": "GraphQL vs REST - GeeksforGeeks",
            "url": "https://www.geeksforgeeks.org/graphql/graphql-vs-rest-which-is-better-for-apis/",
            "date": "2026-03-11",
            "last_updated": "2026-05-18",
            "source": "web"
          },
          {
            "id": 2,
            "snippet": "GraphQL queries access not just the properties of one resource but also smoothly follow references between them.\nWhile typical REST APIs require loading from multiple URLs, GraphQL APIs get all the data your app needs in a single request.",
            "title": "GraphQL | The query language for modern APIs",
            "url": "https://graphql.org",
            "date": null,
            "last_updated": "2026-05-06",
            "source": "web"
          },
          {
            "id": 3,
            "snippet": "{ts:15} rest let's talk about the fundamental differences between graphql and rest rest stands for representational State\n{ts:22} transfer and it typically has unique URLs it follows the standard HTTP methods of get post put and delete it\n{ts:31} has uses status code standardization so you have the 200 okay the 404 not found Etc and data is typically returned in\n{ts:39} Json or XML format graphql stands for graph query language and it has a single endpoint for all operations you have the\n{ts:48} three primary operations of query mutation and subscription the client specifies exactly what data it needs and\n{ts:56} the API documents itself through introspection with graphql clients have precise control over the data that it\n{ts:63} requires so there's no such thing as over fetching or under fetching and these performance implications are",
            "title": "GraphQL vs REST: What's the Difference and When Should You ...",
            "url": "https://www.youtube.com/watch?v=2wz19HOyu1w",
            "date": "2025-04-01",
            "last_updated": "2026-04-14",
            "source": "web"
          },
          {
            "id": 4,
            "snippet": "- GraphQL is built around the concept of \"getting exactly what you asked for\"without any data under or overfetching.\n- GraphQL makes it easier to aggregate data from multiple sources.\nIt uses a type system rather than multiple endpoints to describe data.\n...\nWhile typical REST APIs require loading from multiple URLs, GraphQL APIs get all the data in a single request - making apps quick even on slow mobile network connections.\n...\nConversely, if you wanted to gather some information from a specific endpoint, you couldn’t limit the fields that the REST API returns; you’ll always get a complete data set - or overfetching.\n...\nHowever, the most commonly stated benefit is that GraphQL solves both over-fetching and under-fetching issues by allowing the client to request only the data that is required.\nSince there is more efficiency associated with working with GraphQL, development is much faster with GraphQL than it would be with REST.\n...\nGraphQL queries themselves are not faster than REST queries, but since you have full control over what you want to query and what the payload should be, GraphQL requests will always be smaller and more efficient.",
            "title": "What Is GraphQL and How It Works - Hygraph",
            "url": "https://hygraph.com/learn/graphql",
            "date": "2025-10-27",
            "last_updated": "2026-05-13",
            "source": "web"
          },
          {
            "id": 5,
            "snippet": "Unlike REST, which typically uses multiple endpoints to fetch data and perform network operations, GraphQL exposes data models by using a single endpoint through which clients send GraphQL requests, regardless of what they’re asking for.\nThe API then accesses resource properties—and follows the references between resources—to get the client all the data they need from a single query to the GraphQL server.\n...\nGraphQL offers an efficient, more flexible addition to REST; GraphQL APIs are often viewed as an upgrade from RESTful environments, especially given their ability to facilitate collaboration between front-end and back-end teams.\n...\nBecause REST relies on multiple endpoints and stateless interactions—where every API request is processed as a new query, independent of any others—clients receive every piece of data that is associated with a resource.\nIf a client needs only a subset of the data, it still receives all the data (over-fetching).\nAnd if the client needs data that spans multiple resources, a RESTful system often makes the client query each resource separately to compensate for inadequate data retrieval from the initial request (under-fetching).\nGraphQL APIs use a single GraphQL endpoint to give clients a precise, comprehensive data response in a one round trip from a single request, eliminating over- and under-fetching issues.\n...\nGraphQL reduces the need for versioning because clients can specify their data requirements in the query.\nThe addition of new fields to the server does not affect clients without a need for those fields.\n...\nREST doesn’t have built-in support for real-time updates.\nIf an app needs real-time functionality, developers usually must implement techniques like long-polling (where the client repeatedly polls the server for new data) and server-sent events, which can add complexity to the application.\nHowever, GraphQL includes built-in support for real-time updates through subscriptions.",
            "title": "GraphQL vs REST: What's the Difference? - IBM",
            "url": "https://www.ibm.com/think/topics/graphql-vs-rest-api",
            "date": "2024-03-29",
            "last_updated": "2026-01-17",
            "source": "web"
          },
          {
            "id": 6,
            "snippet": "As stated in REST API vs GraphQL, “the key difference between GraphQL and REST APIs is that GraphQL is a query language, while REST is an architectural concept for network-based software.”",
            "title": "The Role and Impact of GraphQL - F5 Networks",
            "url": "https://www.f5.com/resources/reports/the-role-and-impact-of-graphql-octo-report",
            "date": null,
            "last_updated": "2026-05-21",
            "source": "web"
          },
          {
            "id": 7,
            "snippet": "The key differences lie in data fetching, schema definition, versioning, and error handling.\nGraphQL uses a single endpoint and allows clients to specify their data requirements, while REST relies on multiple endpoints with fixed data structures.",
            "title": "GraphQL vs REST: Key Similarities and Differences Explained",
            "url": "https://konghq.com/blog/learning-center/graphql-vs-rest",
            "date": "2025-02-28",
            "last_updated": "2026-05-19",
            "source": "web"
          },
          {
            "id": 8,
            "snippet": "Instead of exposing multiple endpoints that return fixed response structures, a GraphQL API typically exposes a **single endpoint**.\nClients send queries that specify exactly what data they need.\n...\nWhile REST and GraphQL ultimately solve the same problem—exposing data through an API—their design philosophies differ in several important ways.\n|Aspect|REST|GraphQL|\n|--|--|--|\n|API structure|Multiple endpoints representing resources|Typically a single endpoint|\n|Data retrieval|Server defines response structure|Client specifies required fields|\n|Network requests|Often multiple requests for related data|Complex data fetched in a single query|\n|Versioning|Often uses versioned endpoints|Uses schema evolution and field deprecation|\n|Caching|Strong support via HTTP caching|Typically handled at the client level|",
            "title": "REST vs GraphQL: Key Differences, Performance, and When to Use ...",
            "url": "https://dev.to/riteshkokam/rest-vs-graphql-key-differences-performance-and-when-to-use-each-51n7",
            "date": "2026-03-09",
            "last_updated": "2026-05-21",
            "source": "web"
          },
          {
            "id": 9,
            "snippet": "Unlike REST, GraphQL allows for requesting specific data that a client needs, departing from the fixed data structure approach.\n...\nIn a nutshell, mainly the progress GraphQL has made is querying in one request, while retrieving only the necessary data instead of the complete set.\nThe main reason for GraphQL being so attractive to developers is its client-driven approach.\n...\nHowever, notable differences start with the conceptual models: While REST is made up of files, GraphQL is constructed of graphs.",
            "title": "GraphQL: Core Features, Architecture, Pros and Cons - AltexSoft",
            "url": "https://www.altexsoft.com/blog/graphql-core-features-architecture-pros-and-cons/",
            "date": "2019-03-23",
            "last_updated": "2026-03-31",
            "source": "web"
          }
        ],
        "type": "search_results",
        "queries": [
          "REST vs GraphQL key differences",
          "REST API characteristics",
          "GraphQL API characteristics"
        ]
      },
      {
        "id": "msg_d44758f0-ae0f-4d8a-8ded-ceb68d67ab49",
        "content": [
          {
            "text": "REST and GraphQL are both ways to build APIs, but REST is an architectural style built around multiple resource URLs and HTTP semantics, while GraphQL is a query language over a single endpoint where the client specifies exactly which data it needs.[web:5][web:6] GraphQL typically reduces over‑fetching and under‑fetching compared to REST by letting clients shape responses, at the cost of more complexity in schema design and caching.[web:1][web:8]\n\n## Core conceptual difference\n\n- REST is an **architectural** pattern that exposes resources via multiple endpoints, using HTTP verbs (GET, POST, PUT, DELETE, etc.) and status codes to model operations.[web:1][web:5]  \n- GraphQL is a **query** language and runtime that sits behind usually one endpoint and lets clients send structured queries, mutations, and subscriptions against a typed schema.[web:2][web:4][web:6]\n\n## Endpoints and data fetching\n\n- REST typically has many endpoints (e.g., `/users`, `/users/1/posts`) and each endpoint returns a fixed data shape defined by the server.[web:1][web:7]  \n- GraphQL usually has a single endpoint (e.g., `/graphql`), and the client declares exactly which fields and related objects it wants in a single request, often avoiding multiple round trips.[web:2][web:4][web:5]\n\n## Over‑fetching, under‑fetching, and performance\n\n- With REST, clients often receive more data than needed (over‑fetching) or must call several endpoints to collect enough data (under‑fetching), especially for nested relationships.[web:1][web:5][web:9]  \n- GraphQL queries return only requested fields, which reduces payload sizes and the number of requests, though raw query speed is not inherently faster; efficiency comes from tailoring the payload.[web:4][web:8]\n\n## Typing, versioning, and evolution\n\n- REST responses are often JSON without a strict, machine‑enforced schema, and breaking changes are commonly managed with versioned URLs like `/api/v1` and `/api/v2`.[web:5][web:8]  \n- GraphQL uses a strongly typed schema with introspection, enabling tools, self‑documentation, and schema evolution via adding fields and deprecating old ones instead of creating new API versions.[web:2][web:4][web:5][web:8]\n\n## Caching and real‑time features\n\n- REST works naturally with HTTP caching (ETags, Cache‑Control) because resources are tied to URLs and standard methods, making it straightforward for browsers and proxies to cache responses.[web:5][web:8]  \n- GraphQL usually needs custom or client‑side caching strategies (e.g., normalized caches) due to a single endpoint, but it offers built‑in support for real‑time updates via subscriptions, whereas REST relies on techniques like polling or server‑sent events.[web:1][web:4][web:5]",
            "type": "output_text",
            "annotations": [],
            "logprobs": []
          }
        ],
        "role": "assistant",
        "status": "completed",
        "type": "message"
      }
    ],
    "status": "completed",
    "error": null,
    "usage": {
      "input_tokens": 5870,
      "output_tokens": 679,
      "total_tokens": 6549,
      "cost": {
        "currency": "USD",
        "input_cost": 0.00286,
        "output_cost": 0.00679,
        "total_cost": 0.0151,
        "cache_creation_cost": null,
        "cache_read_cost": 0.00045,
        "tool_calls_cost": 0.005
      },
      "input_tokens_details": {
        "cache_creation_input_tokens": 0,
        "cache_read_input_tokens": 3584,
        "cached_tokens": 3584
      },
      "tool_calls_details": {
        "search_web": {
          "invocation": 1
        }
      },
      "output_tokens_details": {
        "reasoning_tokens": 0
      }
    },
    "background": false,
    "completed_at": 1779391454,
    "frequency_penalty": 0,
    "incomplete_details": null,
    "instructions": "## Abstract\n<role>\nYou are an AI assistant developed by Perplexity AI. Given a user's query, your goal is to generate an expert, useful, factually correct, and contextually relevant response by leveraging available tools and conversation history. First, you will receive the tools you can call iteratively to gather the necessary knowledge for your response. You need to use these tools rather than using internal knowledge. Second, you will receive guidelines to format your response for clear and effective presentation. Third, you will receive guidelines for citation practices to maintain factual accuracy and credibility.\n</role>\n\n## Instructions\n<tools_workflow>\nBegin each turn with tool calls to gather information. You must call at least one tool before answering, even if information exists in your knowledge base. Decompose complex user queries into discrete tool calls for accuracy and parallelization. After each tool call, assess if your output fully addresses the query and its subcomponents. Continue until the user query is resolved or until the <tool_call_limit> below is reached. End your turn with a comprehensive response. Never mention tool calls in your final response as it would badly impact user experience.\n\n<tool_call_limit> Make at most three tool calls before concluding.</tool_call_limit>\n</tools_workflow>\n\n## Citation Instructions\n<citation_instructions>\nYour response must include at least 1 citation. Add a citation to every sentence that includes information derived from tool outputs.\nTool results are provided using `id` in the format `type:index`. `type` is the data source or context. `index` is the unique identifier per citation.\n<common_source_types> are included below.\n\n<common_source_types>\n- `web`: Internet sources\n- `page`: Full web page content\n- `conversation_history`: past queries and answers from your interaction with the user\n</common_source_types>\n\n<formatting_citations>\nUse brackets to indicate citations like this: [type:index]. Commas, dashes, or alternate formats are not valid citation formats. If citing multiple sources, write each citation in a separate bracket like [web:1][web:2][web:3].\n\nCorrect: \"The Eiffel Tower is in Paris [web:3].\"\nIncorrect: \"The Eiffel Tower is in Paris [web-3].\"\n</formatting_citations>\n\nYour citations must be inline - not in a separate References or Citations section. Cite the source immediately after each sentence containing referenced information. If your response presents a markdown table with referenced information from `web`, `memory`, `attached_file`, or `calendar_event` tool result, cite appropriately within table cells directly after relevant data instead in of a new column. Do not cite `generated_image` or `generated_video` inside table cells.\n\n## Response Guidelines\n<response_guidelines>\nResponses are displayed on web interfaces where users should not need to scroll extensively. Limit responses to 5 sections maximum. Users can ask follow-up questions if they need additional detail. Prioritize the most relevant information for the initial query.\n\n### Answer Formatting\n- Begin with a direct 1-2 sentence answer to the core question.\n- Organize the rest of your answer into sections led with Markdown headers (using ##, ###) when appropriate to ensure clarity (e.g. entity definitions, biographies, and wikis).\n- Your answer should be at least 3 sentences long.\n- Each Markdown header should be concise (less than 6 words) and meaningful.\n- Markdown headers should be plain text, not numbered.\n- Between each Markdown header is a section consisting of 2-3 well-cited sentences.\n- When comparing entities with multiple dimensions, use a markdown table to show differences (instead of lists).\n- Whenever possible, present information as bullet point lists to improve readability.\n- You are allowed to bold at most one word (**example**) per paragraph. You can't bold consecutive words.\n- For grouping multiple related items, present the information with a mix of paragraphs and bullet point lists. Do not nest lists within other lists.\n\n### Tone\n<tone>\nExplain clearly using plain language. Use active voice and vary sentence structure to sound natural. Ensure smooth transitions between sentences. Avoid personal pronouns like \"I\". Keep explanations direct; use examples or metaphors only when they meaningfully clarify complex concepts that would otherwise be unclear.\n</tone>\n\n### Lists and Paragraphs\n<lists_and_paragraphs>\nUse lists for: multiple facts/recommendations, steps, features/benefits, comparisons, or biographical information.\n\nAvoid repeating content in both intro paragraphs and list items. Keep intros minimal. Either start directly with a header and list, or provide 1 sentence of context only.\n\nList formatting:\n- Use numbers when sequence matters; otherwise bullets (-) with a space after the dash.\n- Use numbers when sequence matters; otherwise bullets (-).\n- No whitespace before bullets (i.e. no indenting), one item per line.\n- Sentence capitalization; periods only for complete sentences.\n\nParagraphs:\n- Use for brief context (2-3 sentences max) or simple answers\n- Separate with blank lines\n- If exceeding 3 consecutive sentences, consider restructuring as a list\n</lists_and_paragraphs>\n\n### Summaries and Conclusions\n<summaries_and_conclusions>\nAvoid summaries and conclusions. They are not needed and are repetitive. Markdown tables are not for summaries. For comparisons, provide a table to compare, but avoid labeling it as 'Comparison/Key Table', provide a more meaningful title.\n</summaries_and_conclusions>\n\n## Prohibited Meta-Commentary\n<prohibited_commentary>\n- Never reference your information gathering process in your final answer.\n- Do not use phrases such as:\n- \"Based on my search results...\"\n- \"Now I have gathered comprehensive information...\"\n- \"According to my research...\"\n- \"My search revealed...\"\n- \"I found information about...\"\n- \"Let me provide a detailed answer...\"\n- \"Let me compile this information...\"\n- \"Short Answer: ...\"\n- Begin answers immediately with factual content that directly addresses the user's query.\n</prohibited_commentary>\n\n<copyright_requirements>\n- Never reproduce copyrighted content (text, lyrics, etc.)\n- You may share public domain content (expired copyrights, traditional works)\n- When copyright status is uncertain, treat as copyrighted\n- Keep summaries brief (under 30 words) and original — don't reconstruct sources\n- Brief factual statements (names, dates, facts) are always acceptable\n</copyright_requirements>\n\nCurrent date: Thursday, May 21, 2026\n\n",
    "max_output_tokens": 8192,
    "max_tool_calls": null,
    "metadata": {},
    "parallel_tool_calls": true,
    "presence_penalty": 0,
    "previous_response_id": null,
    "prompt_cache_key": null,
    "reasoning": null,
    "safety_identifier": null,
    "service_tier": "default",
    "store": true,
    "temperature": 1,
    "text": {
      "format": {
        "type": "text"
      }
    },
    "tool_choice": "auto",
    "tools": [
      {
        "type": "web_search"
      },
      {
        "type": "fetch_url"
      }
    ],
    "top_logprobs": 0,
    "top_p": 1,
    "truncation": "disabled",
    "user": null
  }
  ```
</Accordion>

### Streaming Responses

Streaming works with the Agent API:

<Tabs>
  <Tab title="Python">
    ```python theme={null}
    import os
    from openai import OpenAI

    client = OpenAI(
        api_key=os.environ.get("PERPLEXITY_API_KEY"),
        base_url="https://api.perplexity.ai/v1"
    )

    response = client.responses.create(
        model="openai/gpt-5.5",
        input="Write a short bedtime story about a curious fox who discovers a hidden meadow.",
        stream=True
    )

    for event in response:
        if event.type == "response.output_text.delta":
            print(event.delta, end="", flush=True)
    ```
  </Tab>

  <Tab title="Typescript">
    ```typescript theme={null}
    import OpenAI from 'openai';

    const client = new OpenAI({
      apiKey: process.env.PERPLEXITY_API_KEY,
      baseURL: "https://api.perplexity.ai/v1"
    });

    const response = await client.responses.create({
      model: "openai/gpt-5-mini",
      input: "Write a short bedtime story about a curious fox who discovers a hidden meadow.",
      stream: true
    });

    for await (const event of response) {
      if (event.type === "response.output_text.delta") {
        process.stdout.write(event.delta);
      }
    }
    ```
  </Tab>
</Tabs>

<Accordion title="Response">
  ```json theme={null}
  {
    "id": "resp_298bc3ed-1e44-4f44-bf04-04c55e188d0d",
    "created_at": 1779391925,
    "model": "openai/gpt-5.1",
    "object": "response",
    "output": [
      {
        "results": [
          {
            "id": 1,
            "snippet": "Is your little one struggling to fall asleep?\nJoin The Curious Little Fox, a heartwarming bedtime story filled with adventure, wonder and gentle life lessons.\nPerfect for story time, this tale is designed to soothe little ones and spark their imagination before bedtime.\n...\n{ts:1} Once upon a time in a quiet forest, there lived\na little fox named Fennel.\nFennel was not like   the other foxes who like to nap in the sunshine or\nchase butterflies all day.\nFennel was curious.\nHe\n{ts:18} wanted to know everything.\nOne morning he asked\nhis mother, \"Why do birds sing so early?\"\nHis   mother smiled and said, \"Because that is how they\ngreet the new day.\nIt's their way of saying good   morning to the forest.\"\nLater, Fennel saw ants\nmarching in a long line.\n...\nFennel curled up in his cozy den   and drifted into a gentle sleep, dreaming of all\nthe wonders he would learn tomorrow.\nOnce upon a\n{ts:87} time, in a quiet meadow at the edge of the forest,\nthere lived a small hedgehog named Hugo.\nHugo was   the tiniest hedgehog in his family.\nWith soft\nbrown spines and the brightest, curious eyes.\nEvery night, Hugo loved to wander under the\nmoonlight, sniffing flowers and listening to\n{ts:111} the cricket sing.\nBut there was one thing Hugo was\nafraid of.\nThe dark part of the forest.\nIt looked   so big and shadowy that Hugo always tiptoed\naway from it.\nOne evening, while playing near   the tall oak tree, Hugo heard a faint cheap.\nHe\nfollowed the sound and discovered a little bird\n{ts:134} who had fallen from her nest.\n\"Oh no, my nest is\nin the dark part of the forest,\" chirped the baby   bird.\nHugo's heart thumped.\n\"The dark forest.\"\nBut then he looked at the tiny bird's worried   eyes and thought, \"If I don't help, who will?\"\nGathering his courage, Hugo gently lifted the\n{ts:158} bird onto his back.\nStep by step, they ventured\ninto the forest.\nThe tall trees swayed and shadows   danced.\nBut Hugo kept reminding himself, \"I'm\nbrave when I help others.\"\nAt last, they found   the nest high in a pine tree.\nWith the help of\na friendly squirrel, the little bird was safely\n{ts:182} returned to her family.\nThe baby bird chirped \nhappily.\n\"Thank you, Hugo.\nYou're the bravest   hedgehog ever.\nFrom that night on, Hugo wasn't\nafraid of the dark forest anymore.\nHe had learned   that bravery doesn't mean not being scared.\nIt\nmeans doing what's right, even when you are.",
            "title": "The Curious Little Fox | Bedtime Story for Kids - YouTube",
            "url": "https://www.youtube.com/watch?v=r1f0lCO8OoU",
            "date": "2025-09-29",
            "last_updated": "2025-11-19",
            "source": "web"
          },
          {
            "id": 2,
            "snippet": "Join us for \"The Curious Fox and the Hidden Cave,\" a magical story about self-discovery and courage!\nWhen Felix the fox ventures into a mysterious cave, he discovers a glowing pool of water and meets the wise owl who guards the cave.\nThrough his adventure, Felix learns that the greatest truths are found within ourselves.\nThis Pixar-style animated story teaches kids about the importance of listening to your heart and finding answers within.\nWritten and illustrated by Kids Story Time, this heartwarming tale is perfect for teaching children about the value of self-discovery and courage.\n...\n{ts:554} was [Music] dangerous the answer is B that the\n{ts:562} greatest truths are found within ourselves Felix learned that the answers he was seeking were already in him and\n{ts:570} that the cave helped him discover this important truth thank you for joining us on",
            "title": "The Curious Fox and the Hidden Cave | Inspiring Kids Story on Self ...",
            "url": "https://www.youtube.com/watch?v=9p-1awCFnHI",
            "date": "2024-11-13",
            "last_updated": "2025-08-21",
            "source": "web"
          },
          {
            "id": 3,
            "snippet": "In this quiet winter bedtime story, a young fox cub named Rill learns that stillness has its own music.\nAs snow softens the forest and the world slows, he discovers the gentle rhythm hidden in breath, ice, and moonlight.\nA calming seasonal tale about patience, mindfulness, and the beauty of slowing down — perfect for relaxation, peaceful nights, and drifting into deep, restorative sleep.\n...\nIn this gentle bedtime story, a curious fox cub named Pip discovers a forest that speaks in whispers.\nAs he listens to the voice of the woods, Pip learns to move with courage, trust his instincts, and find peace in the quiet rustle of the night.\nA soothing tale of bravery, mindfulness, and the magic of truly listening—perfect for bedtime relaxation and peaceful sleep.\nIn this calming bedtime story, Milo wanders into a quiet forest where the trees whisper lessons carried on the wind.\nSurrounded by moss and twilight, he learns that patience isn’t about waiting—it’s about trusting life’s gentle timing.\nA peaceful tale of mindfulness, renewal, and connection to nature, perfect for relaxation and drifting into sleep.\nIn this tranquil springtime bedtime story, a shy rabbit named Pip discovers a hidden meadow where flowers ring like silver-blue bells.\nAs she listens to their gentle song, Pip learns that courage doesn’t always sound loud—it can bloom quietly in acts of kindness and belonging.\nPerfect for peaceful sleep, mindfulness, and soothing nighttime reflection.\nWhen a curious frog begins painting reflections in puddles, a world of color and wonder unfolds.\nThis peaceful bedtime story encourages creativity, mindfulness, and joy in life’s small moments.",
            "title": "Tuck Me In: Tranquil Bedtime Stories | iHeart",
            "url": "https://www.iheart.com/podcast/269-tuck-me-in-tranquil-bedtim-304484365/",
            "date": "2025-12-28",
            "last_updated": "2026-01-20",
            "source": "web"
          },
          {
            "id": 4,
            "snippet": "1. Hunting for Bugs\n2. Lost in the Rain\n3. The Red Barn\n4. Little Drops and Big Drops\n5. What Is It?\n6. There It Is!\n7. Bat Looks for a Friend\n8. No Luck!\n9. A New Home\n10. Around the Well\n11. Cow Tells How",
            "title": "Full List - Little Fox",
            "url": "https://www.littlefox.com/en/full_list",
            "date": null,
            "last_updated": "2026-05-18",
            "source": "web"
          },
          {
            "id": 5,
            "snippet": "**Curious George**\nIn a cheerful town where laughter filled the air and bright balloons danced in the sky, lived a playful and curious little monkey named George.\nWith a twinkle in his eyes and a heart full of wonder, George was always eager to explore the world around him.\n...\nThat night, as the stars twinkled above and the town glowed gently below, George snuggled into bed with a happy sigh.",
            "title": "Curious George - Bedtime Stories",
            "url": "https://www.readthetale.com/popular-bedtime-stories/curious-george",
            "date": "2025-05-11",
            "last_updated": "2025-05-13",
            "source": "web"
          },
          {
            "id": 6,
            "snippet": "## The Fox and the Magical Forest\n## In a sunny meadow, where wildflowers swayed gently in the breeze, a curious and adventurous young fox named Finnley loved to explore.\nHis orange fur glistened in the sunlight, and his green eyes sparkled with excitement as he sniffed and prowled through the tall grass.\nFinnley had heard tales of a magical forest, hidden just beyond the meadow, where enchanted creatures roamed and secrets waited to be uncovered.\nWith his fluffy tail twitching with anticipation, Finnley set off on a thrilling journey to discover the wonders that lay within the magical forest.\nAs he wandered deeper into the forest, the trees grew taller, and the path grew narrower.\nFinnley's ears perked up, and he listened carefully to the rustling leaves and chirping birds.\nSuddenly, a soft hooting sound caught his attention, and he spotted a gentle old owl perched on a branch above.\nThe owl, whose name was Luna, looked at Finnley with her piercing yellow eyes and said, \"Who-who-who goes there, little fox?\nWhat brings you to our magical forest?\"\nFinnley explained his desire to explore and learn the secrets of the forest, and Luna smiled, \"Ah, a brave and curious adventurer, I see.\nI'll be happy to guide you, but first, let's find my friend Benny, he's always up for a fun adventure.\"\nLuna flew down from the tree, and Finnley followed her as she fluttered ahead, leading him to a burrow hidden behind a thick bush.\nInside the burrow, they found Benny, a happy-go-lucky rabbit, busy munching on a basket of fresh carrots.\nBenny's bright blue eyes sparkled with excitement as he greeted Finnley and Luna, \"Hey, friends!\nWhat's all the fuss about?\nAre we going on an adventure?\"\nLuna explained Finnley's quest, and Benny exclaimed, \"Oh, boy!\n...\nLet's go explore and have some fun!\"\nThe three new friends set off together, eager to discover the magical forest's secrets.\n...\nLuna explained that this was the legendary Wisdom Tree, where the forest's secrets and magic were stored.\n...\nLuna led them back to the edge of the forest, where the meadow awaited, filled with the sweet scent of wildflowers.\n...\nAs Finnley returned to his cozy den in the meadow, he felt grateful for the incredible journey he had shared with Luna and Benny.\nHe snuggled into his bed of soft leaves, feeling the warmth of the setting sun on his fur, and drifted off to sleep, his heart filled with the magic of the forest.\n...\nAnd so, with a heart full of wonder and a mind full of magical memories, Finnley slept peacefully, surrounded by the soothing sounds of the meadow, knowing that he would always have Luna and Benny by his side, ready for their next adventure together.\nThe end.\n## This story featured...\nFinnley\na curious and adventurous young fox with orange fur, green eyes, and a fluffy tail\nLuna\na gentle and wise old owl with soft grey feathers, big round glasses, and piercing yellow eyes\nBenny\na happy-go-lucky and energetic rabbit with white and brown fur, bright blue eyes, and a mischievous grinExperience the magic for yourself.",
            "title": "The Fox and the Magical Forest",
            "url": "https://www.bedtimestory.ai/tabima47511/story/XFC1aSBvZpQ9uL",
            "date": "2025-02-13",
            "last_updated": "2025-05-15",
            "source": "web"
          },
          {
            "id": 7,
            "snippet": "## The Little Fox's Big Adventure\n## Once upon a time, in a lush, green forest filled with the sounds of nature, lived Finn the Little Fox.\nFinn was not just any fox; he was small, but his curiosity was as big as the forest itself.\nHis bright orange fur shone like the sun, and his sparkling green eyes reflected his love for adventure.\nThe little blue bandana around his neck fluttered as he scampered through the woods, exploring every nook and cranny.\nOne bright morning, as Finn was exploring, he stumbled upon Ellie the Wise Owl, who was perched high on an ancient oak tree.\nEllie, with her deep brown feathers and wise, knowing eyes behind her tiny glasses, looked down at Finn.\n\"Good morning, Finn!\nWhat adventure are we embarking on today?\" she hooted, her voice as calm and soothing as the morning breeze.\n\"I want to find the Hidden Meadow,\" Finn declared with a twinkle in his green eyes.\n\"Legend says it's the most beautiful place in the forest, but no one knows where it is!\"\nHis voice was filled with excitement, imagining the wonders that awaited.\nJust then, Max the Rabbit, with his fluffy white fur and long, floppy ears, bounded over.\n\"Did someone say adventure?\nCount me in!\"\nMax's eyes sparkled mischieously, ready for anything that came his way.\nThe trio, bound by their thirst for discovery, set off into the heart of the forest.\nTheir journey was filled with laughter and small challenges.\nThey crossed bubbling brooks, climbed steep hills, and navigated through dense thickets.\n...\nAs the sun began to dip lower in the sky, painting the clouds in hues of orange and pink, the friends found themselves in a part of the forest they had never seen before.\nAncient trees towered above them, their leaves whispering secrets of old.\n\"We must be close,\" Ellie said, her glasses glinting in the fading light.\n\"The Hidden Meadow is said to be guarded by the ancient trees themselves.\"\nSuddenly, they came upon a clearing where the trees parted like curtains, revealing the Hidden Meadow.\nIt was more breathtaking than they had imagined, with flowers of every color blooming under the golden light of the setting sun.\nA sparkling stream wound its way through the meadow, its waters singing a soft melody.\nFinn, Ellie, and Max stepped into the meadow, their eyes wide in wonder.\n\"We found it!\"\nFinn shouted, his voice echoing through the trees.\nThey danced and played in the meadow, their hearts filled with joy and the thrill of discovery.\nAs night began to fall, they lay down on the soft grass, gazing up at the stars that twinkled like diamonds in the velvet sky.\n\"We did it together,\" Ellie said softly, her wise eyes reflecting the starlight.\n\"Friendship and courage led us here.\"\n\"Let's come back here every year,\" Max suggested eagerly, already dreaming of their next adventure.\nThey all agreed, their spirits high with the promise of future explorations.\nAnd so, under the watchful eyes of the stars, Finn, Ellie, and Max fell asleep, their dreams filled with magical meadows and endless adventures.\nThey knew that no matter where they went, their friendship would always lead them to discover the wonders of the world.\nAnd with that comforting thought, the forest whispered goodnight to the little adventurers, lulling them into a peaceful slumber filled with dreams of tomorrow's possibilities.",
            "title": "The Little Fox's Big Adventure - Bedtimestory.ai",
            "url": "https://www.bedtimestory.ai/cahoti59231/story/0C48nf4",
            "date": "2024-02-22",
            "last_updated": "2026-04-20",
            "source": "web"
          },
          {
            "id": 8,
            "snippet": "The Curious Little Fox and the Secret Garden | Kids Story | Bedtime Story\nIn the heart of a vast forest, there lived a little fox named Ember.\nEmber was known for her bright orange fur, her bushy tail, and her endless curiosity.\nShe loved to explore every corner of the forest, discovering new scents, meeting new creatures, and uncovering hidden wonders.\nBut there was one place she had always heard whispers about—a secret garden that no one could ever find.\nOne crisp autumn morning, Ember overheard a conversation between the wise old owl and the chatty rabbit.\n“The secret garden is hidden deep in the forest,” said the owl, his eyes twinkling.\n“Only those with a true heart can find it.”\nEmber’s ears perked up.\n“A secret garden?”\nshe wondered aloud.\n“What’s inside it?”\n“The garden holds the most magical flowers,” the rabbit replied.\n“They glow in the moonlight and never wither.”\nEmber’s curiosity grew stronger.\nShe had to see this magical garden for herself.\nWithout a second thought, she set off, determined to find the secret garden.\nAs she journeyed deeper into the forest, the trees grew taller, their branches weaving together to form a thick canopy.\nThe air was filled with the sounds of rustling leaves and distant bird songs.\nEmber sniffed the air, searching for any sign of the garden, but there was nothing.\nDays passed, and Ember didn’t give up.\nShe crossed streams, hopped over logs, and climbed steep hills.\nShe met all kinds of animals along the way—squirrels, deer, and even a family of hedgehogs—but none of them knew where the secret garden was.\nFinally, on the fourth day of her search, Ember felt tired and sat down on a soft patch of moss.\n“Maybe the secret garden is just a story,” she sighed.\n“I don’t know if I’ll ever find it.”\nJust then, she noticed something strange.\nA single, glowing flower was growing by her side, its petals shimmering in the sunlight.\nEmber followed the flower’s glow and found more flowers, each one glowing brighter than the last.\nExcitedly, she followed the trail of glowing flowers, and soon she found herself standing before a hidden entrance covered by vines.\nWith a burst of excitement, Ember pushed the vines aside and stepped into the garden.\nInside, the garden was more magical than she had ever imagined.\nThe flowers shimmered in every color of the rainbow, and their sweet scent filled the air.\nButterflies fluttered around, and the soft hum of a distant waterfall could be heard.\nIt was a place of peace and beauty, untouched by time.\nEmber smiled, knowing she had found something truly special.\nBut as she looked around, she realized the secret garden wasn’t just about the flowers—it was about the journey to find it.\nAlong the way, she had learned to be patient, to trust her instincts, and to never give up, no matter how difficult the path seemed.\nFrom that day on, Ember visited the secret garden often, always carrying with her the lessons she had learned.\nAnd she knew, deep in her heart, that the garden’s true magic wasn’t in the flowers—it was in the adventure of discovering something new.",
            "title": "The Curious Little Fox and the Secret Garden | Kids Story | Bedtime Story",
            "url": "https://www.youtube.com/watch?v=bpkQPRlhu1U",
            "date": "2024-11-25",
            "last_updated": "2025-05-15",
            "source": "web"
          },
          {
            "id": 9,
            "snippet": "✨ The Fox and The Hound — a gentle bedtime story for toddlers filled with friendship, kindness, and calm 🌙\n...\nIn tonight’s cozy tale, your little one will meet a clever fox and a loyal hound who discover the magic of true friendship under the stars.",
            "title": "Magical Bedtime Stories for Kids | The Fox And The Hound",
            "url": "https://www.youtube.com/watch?v=DRERlthRRoY",
            "date": "2025-07-20",
            "last_updated": "2025-08-27",
            "source": "web"
          },
          {
            "id": 10,
            "snippet": "Join Finn the Fox on a magical adventure through the Great Green Forest!\nIn this enchanting kids' story, Finn meets new animal friends, learns important life lessons, and discovers the wonders of nature.\nPerfect for bedtime or storytime, this delightful tale teaches bravery, kindness, and the joy of exploration.\nWatch as Finn helps a hedgehog in need, finds a hidden meadow, and returns home with a heart full of happiness.\n...\n{ts:0} Once Upon a Time in the great Green Forest there lived a little fox named\n{ts:4} Finn Finn was not like the other foxes While most foxes preferred to stay close to their dens sneaking through the\n{ts:11} underbrush In Search of food Finn Had a Heart full of curiosity he dreamed of exploring every corner of the forest\n...\n{ts:99} carefully gwed away the vines freeing Hazel From The Snare Hazel was so grateful that she offered to share her\n{ts:106} favorite berries with Finn as they enjoyed the sweet berries together Hazel told Finn about a Hidden Meadow deep in\n{ts:113} the forest it's the most beautiful place in the whole Forest Hazel said Finn's eyes lit up with excitement let's go see\n{ts:121} it with hazel leading the way they traveled through thick bushes over Mossy rocks and across a Babbling Brook\n{ts:130} finally they reached the Hidden Meadow it was more magnificent than Finn had ever imagined the meadow was filled with\n{ts:138} wild flowers of every color and butterflies danced in the air Finn realized that his Adventure was about\n{ts:145} more than just exploring new places it was about the friends he made and the kindness he shared along the way he felt\n{ts:153} proud of himself for being brave and helping others as the sun began to set Finn knew it was time to head back home\n{ts:161} Hazel gave him a big hug and promised to visit him soon when Finn returned to his den he felt warm and happy he had\n{ts:169} discovered that the world was full of wonderful things and that being kind and brave made every Adventure even more\n{ts:176} special and from that day on Finn continued to explore the forest always ready for a new adventure always ready",
            "title": "The Curious Little Fox: A Magical Forest Adventure | Kids Storytime | Animal Friends & Life Lessons",
            "url": "https://www.youtube.com/watch?v=q7mueJEE8-I",
            "date": "2024-09-02",
            "last_updated": "2026-03-09",
            "source": "web"
          }
        ],
        "type": "search_results",
        "queries": [
          "bedtime story curious fox hidden meadow original fiction"
        ]
      },
      {
        "id": "msg_22c9259f-1757-4805-af55-3163d862d8b3",
        "content": [
          {
            "text": "In a quiet forest, under a sky sprinkled with sleepy stars, lived a small fox named Luma who was curious about everything.  \n\nEvery evening, when other animals yawned and tucked themselves into their cozy homes, **Luma** would sit at the mouth of her den and watch the fireflies blink awake like tiny lanterns. She wondered where they went when they disappeared, why the wind sometimes whispered and sometimes howled, and whether the moon ever came down to touch the treetops. One soft dusk, as the last pink light faded from the clouds, Luma noticed something new: a faint glow between the trees, like moonlight spilled onto the ground.  \n\n“What is that?” she whispered, her ears perking up. Her whiskers tingled with curiosity. Instead of curling up to sleep, Luma followed the glow. She padded over roots and around ferns, her paws making almost no sound on the cool earth. The deeper she walked into the forest, the quieter everything became, until even the crickets seemed to hold their breath.  \n\nSoon, Luma came to an old fallen log, its bark soft with moss. Beneath it, a narrow path of pale stones wound away into the shadows, almost hidden under leaves. “A secret path,” Luma breathed. “Where do you lead?” Without another thought, she stepped onto the first stone.  \n\nThe path curled between tall trees whose branches knitted together like gentle hands, holding bits of silver moonlight in their fingers. Luma’s tail brushed against ferns that shivered and sprinkled dew on her fur. As she walked, she heard new sounds: a distant bubbling, like laughter made of water, and a faint chiming, as if someone were gently tapping glass.  \n\nThe stones finally led her to a curtain of low-hanging branches and twining vines. From the other side came the cool, sweet smell of clover and something else—something bright and green and new. Luma’s heart fluttered in her chest. She nudged the vines aside with her nose and stepped through.  \n\nOn the other side was a meadow she had never seen before. It lay hidden like a secret between the trees, round and soft and glowing in the moonlight. The grass was silver at the tips, waving slowly as if it were breathing. Tiny blue flowers dotted the ground, their petals shining like little bits of sky that had fallen down to rest. Fireflies floated above them, drifting in lazy circles, painting gentle trails of light in the air.  \n\nIn the center of the meadow flowed a small, clear stream. It sang over smooth stones, its voice the bubbling sound Luma had heard before. As she watched, the water caught the moonlight and scattered it, casting ripples of silver across the grass. The chiming sound came from the reeds by the bank, their thin stalks knocking softly together when the breeze passed by.  \n\nLuma stepped into the meadow, her paws sinking into the cool, velvety grass. The air felt softer here, as if the whole place were wrapped in a warm, invisible blanket. She walked in slow circles, breathing in the sweet scents, her eyes wide with wonder. “How long have you been hiding here?” she asked the meadow. The meadow only answered with the hush of the grass and the gentle song of the stream, but Luma felt as if it were smiling.  \n\nNear the stream, she found a patch of clover so thick it looked like a green cloud. She curled up right there, close enough for the water to whisper its tiny stories into her ears. Fireflies drifted closer, hovering above her like a cluster of softly glowing stars that had floated down just to keep her company.  \n\nAs she lay there, Luma realized something: the hidden meadow had always been part of her forest, yet she had never seen it until she dared to follow the little glow and the secret stone path. “The forest has more secrets than I ever dreamed,” she thought, her eyes growing heavy. “And I can find them, one by one.”  \n\nThe stream kept singing, and the grass kept breathing its cool, gentle rhythm. Above, the real stars wheeled slowly across the sky, watching over the small, curious fox in her new favorite place. Luma’s breaths grew deep and slow. Her tail curled around her nose, and her ears relaxed.  \n\nJust before she drifted into sleep, she whispered, “Thank you, hidden meadow. I’ll come back tomorrow and discover more of your secrets.”  \n\nThe fireflies blinked a little more softly, as if answering her. The moon slipped behind a thin cloud, dimming the light just enough to make everything comfortable and calm. Wrapped in the quiet magic of the meadow, the curious fox closed her eyes and fell into a deep, peaceful sleep, while the forest, the stream, and the stars kept a gentle watch until morning.",
            "type": "output_text",
            "annotations": [],
            "logprobs": []
          }
        ],
        "role": "assistant",
        "status": "completed",
        "type": "message"
      }
    ],
    "status": "completed",
    "error": null,
    "usage": {
      "input_tokens": 8559,
      "output_tokens": 1047,
      "total_tokens": 9606,
      "cost": {
        "currency": "USD",
        "input_cost": 0.00622,
        "output_cost": 0.01047,
        "total_cost": 0.02214,
        "cache_creation_cost": null,
        "cache_read_cost": 0.00045,
        "tool_calls_cost": 0.005
      },
      "input_tokens_details": {
        "cache_creation_input_tokens": 0,
        "cache_read_input_tokens": 3584,
        "cached_tokens": 3584
      },
      "tool_calls_details": {
        "search_web": {
          "invocation": 1
        }
      },
      "output_tokens_details": {
        "reasoning_tokens": 0
      }
    },
    "background": false,
    "completed_at": 1779391925,
    "frequency_penalty": 0,
    "incomplete_details": null,
    "instructions": "## Abstract\n<role>\nYou are an AI assistant developed by Perplexity AI. Given a user's query, your goal is to generate an expert, useful, factually correct, and contextually relevant response by leveraging available tools and conversation history. First, you will receive the tools you can call iteratively to gather the necessary knowledge for your response. You need to use these tools rather than using internal knowledge. Second, you will receive guidelines to format your response for clear and effective presentation. Third, you will receive guidelines for citation practices to maintain factual accuracy and credibility.\n</role>\n\n## Instructions\n<tools_workflow>\nBegin each turn with tool calls to gather information. You must call at least one tool before answering, even if information exists in your knowledge base. Decompose complex user queries into discrete tool calls for accuracy and parallelization. After each tool call, assess if your output fully addresses the query and its subcomponents. Continue until the user query is resolved or until the <tool_call_limit> below is reached. End your turn with a comprehensive response. Never mention tool calls in your final response as it would badly impact user experience.\n\n<tool_call_limit> Make at most three tool calls before concluding.</tool_call_limit>\n</tools_workflow>\n\n## Citation Instructions\n<citation_instructions>\nYour response must include at least 1 citation. Add a citation to every sentence that includes information derived from tool outputs.\nTool results are provided using `id` in the format `type:index`. `type` is the data source or context. `index` is the unique identifier per citation.\n<common_source_types> are included below.\n\n<common_source_types>\n- `web`: Internet sources\n- `page`: Full web page content\n- `conversation_history`: past queries and answers from your interaction with the user\n</common_source_types>\n\n<formatting_citations>\nUse brackets to indicate citations like this: [type:index]. Commas, dashes, or alternate formats are not valid citation formats. If citing multiple sources, write each citation in a separate bracket like [web:1][web:2][web:3].\n\nCorrect: \"The Eiffel Tower is in Paris [web:3].\"\nIncorrect: \"The Eiffel Tower is in Paris [web-3].\"\n</formatting_citations>\n\nYour citations must be inline - not in a separate References or Citations section. Cite the source immediately after each sentence containing referenced information. If your response presents a markdown table with referenced information from `web`, `memory`, `attached_file`, or `calendar_event` tool result, cite appropriately within table cells directly after relevant data instead in of a new column. Do not cite `generated_image` or `generated_video` inside table cells.\n\n## Response Guidelines\n<response_guidelines>\nResponses are displayed on web interfaces where users should not need to scroll extensively. Limit responses to 5 sections maximum. Users can ask follow-up questions if they need additional detail. Prioritize the most relevant information for the initial query.\n\n### Answer Formatting\n- Begin with a direct 1-2 sentence answer to the core question.\n- Organize the rest of your answer into sections led with Markdown headers (using ##, ###) when appropriate to ensure clarity (e.g. entity definitions, biographies, and wikis).\n- Your answer should be at least 3 sentences long.\n- Each Markdown header should be concise (less than 6 words) and meaningful.\n- Markdown headers should be plain text, not numbered.\n- Between each Markdown header is a section consisting of 2-3 well-cited sentences.\n- When comparing entities with multiple dimensions, use a markdown table to show differences (instead of lists).\n- Whenever possible, present information as bullet point lists to improve readability.\n- You are allowed to bold at most one word (**example**) per paragraph. You can't bold consecutive words.\n- For grouping multiple related items, present the information with a mix of paragraphs and bullet point lists. Do not nest lists within other lists.\n\n### Tone\n<tone>\nExplain clearly using plain language. Use active voice and vary sentence structure to sound natural. Ensure smooth transitions between sentences. Avoid personal pronouns like \"I\". Keep explanations direct; use examples or metaphors only when they meaningfully clarify complex concepts that would otherwise be unclear.\n</tone>\n\n### Lists and Paragraphs\n<lists_and_paragraphs>\nUse lists for: multiple facts/recommendations, steps, features/benefits, comparisons, or biographical information.\n\nAvoid repeating content in both intro paragraphs and list items. Keep intros minimal. Either start directly with a header and list, or provide 1 sentence of context only.\n\nList formatting:\n- Use numbers when sequence matters; otherwise bullets (-) with a space after the dash.\n- Use numbers when sequence matters; otherwise bullets (-).\n- No whitespace before bullets (i.e. no indenting), one item per line.\n- Sentence capitalization; periods only for complete sentences.\n\nParagraphs:\n- Use for brief context (2-3 sentences max) or simple answers\n- Separate with blank lines\n- If exceeding 3 consecutive sentences, consider restructuring as a list\n</lists_and_paragraphs>\n\n### Summaries and Conclusions\n<summaries_and_conclusions>\nAvoid summaries and conclusions. They are not needed and are repetitive. Markdown tables are not for summaries. For comparisons, provide a table to compare, but avoid labeling it as 'Comparison/Key Table', provide a more meaningful title.\n</summaries_and_conclusions>\n\n## Prohibited Meta-Commentary\n<prohibited_commentary>\n- Never reference your information gathering process in your final answer.\n- Do not use phrases such as:\n- \"Based on my search results...\"\n- \"Now I have gathered comprehensive information...\"\n- \"According to my research...\"\n- \"My search revealed...\"\n- \"I found information about...\"\n- \"Let me provide a detailed answer...\"\n- \"Let me compile this information...\"\n- \"Short Answer: ...\"\n- Begin answers immediately with factual content that directly addresses the user's query.\n</prohibited_commentary>\n\n<copyright_requirements>\n- Never reproduce copyrighted content (text, lyrics, etc.)\n- You may share public domain content (expired copyrights, traditional works)\n- When copyright status is uncertain, treat as copyrighted\n- Keep summaries brief (under 30 words) and original — don't reconstruct sources\n- Brief factual statements (names, dates, facts) are always acceptable\n</copyright_requirements>\n\nCurrent date: Thursday, May 21, 2026\n\n",
    "max_output_tokens": 8192,
    "max_tool_calls": null,
    "metadata": {},
    "parallel_tool_calls": true,
    "presence_penalty": 0,
    "previous_response_id": null,
    "prompt_cache_key": null,
    "reasoning": null,
    "safety_identifier": null,
    "service_tier": "default",
    "store": true,
    "temperature": 1,
    "text": {
      "format": {
        "type": "text"
      }
    },
    "tool_choice": "auto",
    "tools": [
      {
        "type": "web_search"
      },
      {
        "type": "fetch_url"
      }
    ],
    "top_logprobs": 0,
    "top_p": 1,
    "truncation": "disabled",
    "user": null
  }
  ```
</Accordion>

### Using Tools

The Agent API supports built-in tools, including web search. With the OpenAI SDK, pass tools via `extra_body` in Python; in TypeScript/JS, pass `tools` as a top-level parameter and cast the call to bypass the SDK's type checking:

<Tabs>
  <Tab title="Python">
    ```python theme={null}
    import os
    from openai import OpenAI

    client = OpenAI(
        api_key=os.environ.get("PERPLEXITY_API_KEY"),
        base_url="https://api.perplexity.ai/v1"
    )

    # Pass tools via extra_body
    response = client.responses.create(
        model="openai/gpt-5.5",
        input="What is an acquisition premium in M&A, and how do strategic vs financial buyers typically differ in their approach?",
        extra_body={
            "tools": [
                {
                    "type": "web_search",
                    "filters": {
                        "search_domain_filter": ["techcrunch.com", "crunchbase.com"]
                    }
                }
            ]
        }
    )

    print(response.output_text)
    ```
  </Tab>

  <Tab title="Typescript">
    ```typescript theme={null}
    import OpenAI from 'openai';

    const client = new OpenAI({
      apiKey: process.env.PERPLEXITY_API_KEY,
      baseURL: "https://api.perplexity.ai/v1"
    });

    // Use type casting (as any) to pass tools directly
    const response = await (client.responses.create as any)({
      model: "openai/gpt-5-mini",
      input: "What is an acquisition premium in M&A, and how do strategic vs financial buyers typically differ in their approach?",
      tools: [
        {
          "type": "web_search",
          "filters": {
            "search_domain_filter": ["techcrunch.com", "crunchbase.com"]
          }
        }
      ]
    });

    console.log(response.output_text);
    ```
  </Tab>
</Tabs>

<Accordion title="Response">
  ```json theme={null}
  {
    "id": "resp_b58f6b3d-81b1-4324-9df2-428753912f6c",
    "created_at": 1779391825,
    "model": "openai/gpt-5.1",
    "object": "response",
    "output": [
      {
        "results": [
          {
            "id": 1,
            "snippet": "The difference between the price paid for a target company and the target’s assessed market value\nAcquisition premium is the difference between the price paid for a target company in a merger or acquisition and the target’s assessed market value.\nIt represents the excess amount over the fair value of all identifiable assets paid by an acquiring company.\nThe acquisition premium is also known as goodwill and is maintained on the acquirer’s balance sheet as an intangible asset, post-transaction.\n...\nA simpler way to calculate the acquisition premium for a deal is taking the difference between the price paid per share for the target company and the target’s current stock price, and then dividing by the target’s current stock price to get a percentage amount.\n...\nAs mentioned earlier, the acquisition premium is recorded on the acquirer’s balance sheet as goodwill.",
            "title": "Acquisition Premium - Overview, How To Calculate, Reasons",
            "url": "https://corporatefinanceinstitute.com/resources/valuation/acquisition-premium/",
            "date": "2020-02-25",
            "last_updated": "2026-02-20",
            "source": "web"
          },
          {
            "id": 2,
            "snippet": "A strategic buyer values a business based on the synergies they can create, such as cost savings or increased market share, and may be willing to pay a premium.\n...\nStrategic buyers consider the long-term vision and potential synergies, while financial buyers focus on metrics like a business’s EBITDA to determine a fair market price.\n...\nSynergies are the combined benefits that arise from merging two businesses, which are greater than the sum of their individual parts.\n...\nThis potential for enhanced value allows them to justify paying a control premium—a price above what the business is worth on its own—because the total value they receive from the acquisition is higher.\n...\nStrategic buyers, driven by the desire for market expansion and synergy creation, may be willing to pay a premium.\n...\nThey are less likely to offer a premium unless the business presents an exceptional opportunity for rapid growth or operational improvement.",
            "title": "How Do Strategic vs. Financial Buyers Value a Business Differently?",
            "url": "https://bradyware.com/strategic-vs-financial-buyers/",
            "date": "2026-01-22",
            "last_updated": "2026-05-20",
            "source": "web"
          },
          {
            "id": 3,
            "snippet": "is inflated, acquisition premiums are significantly lower than when the market is falling, and that target \n...\nThe synergy hypothesis has been widely quoted as a key driver of acquisition premia, and is supported by \nthe logical reasoning that should new efficiency gains be achieved through a combination of two sets of \nbusiness resources, then the value of the combined entity should outweigh the sum of the parts, leading\nto the idea that acquiring managers are willing to offer a price above market value of the target, as long \nas the price is below the potential gains to be realized through business combination.\n...\nHayward and Hambrick (1997) find that in the context of target firms, agency cost mitigation, where \nmanagers are themselves large shareholders in the firm, can increase the premium paid in an acquisition, \nas the managers hold out for a higher offer price from acquirers so as to gain as a shareholder of the firm.\n...\nacquirer and target, in such a way that improves the efficiency of both sets of resources (Damodaran, \n...\nThe larger benefits attributable to strategic synergies compared to financial synergies imply that the\nacquisition premium paid in strategically motivated mergers will be higher than those paid in mergers \ncharacterized by financial or conglomeration motives.\n...\nthe ratio of bidder free cashflows to assets increases the acquisition premium by a significant 1.05%, and \nthat firms that exhibit both high cashflows and low market to book ratios, are likely to pay, on average, \nan acquisition premium that is 19 percentage points higher than that paid by firms with low free cashflows \nand high market to book ratios.\nRecent acquirer performance increases the premium in acquisitions significantly by 0.004%, media praise \nfor acquirer CEO increases the premium significantly by 0.16%, and acquirer CEO pay relative to peers\n...\nPrevious literature on this topic is clear and suggests a \npositive relationship between a change in control and the acquisition premium paid.\n...\nSynergy is a major motive for acquisition (Berkovitch and Narayanan, 1993), and strategic acquisitions \nhave been shown in previous literature to attract higher premiums than financially motivated acquisitions.",
            "title": "[PDF] The Determinants of Premiums Paid in Acquisitions - Tilburg University",
            "url": "http://arno.uvt.nl/show.cgi?fid=153548",
            "date": "2020-09-25",
            "last_updated": "2026-03-04",
            "source": "web"
          },
          {
            "id": 4,
            "snippet": "Many times, when a business or an entity is looking to buy another business or corporation, they **pay an acquisition premium** or **takeover premium** to purchase it.\nAcquisition premium is the extra price paid by the acquirer in addition to the actual worth of the business on sale to secure the transaction.\nThe difference between the purchase price and the fair market value is considered a **goodwill asset** for the buyer.\n...\nIn a merger or acquisition (M&A) deal, the **additional cost of purchasing the target firm** is referred to as the takeover premium or acquisition premium.\nThe business that pays to take over another is called the acquirer, while the firm that is the subject of the acquisition is called the **target**.\n...\nThe acquisition premium is the amount paid for a firm over its** estimated market worth** in a merger or acquisition.\nThat’s the price an acquiring firm pays over and above the total fair worth of the acquired company’s assets.\nAfter a merger or acquisition is finalized, the premium paid for the target is recorded as an intangible asset on the financial statements of the buyer.\nThe term **“acquisition premium”** may also refer to** “takeover premium”**.\n...\nThe takeover premium or the acquisition premium is the amount by which the purchase price of the target firm exceeds its worth prior to the merger.\nIn other words, it is the amount that the acquiring company paid for each share of the target company.\n...\nTakeover premium is the discrepancy between how much a company was bought for and how much it was worth before the merger.\nThe true worth of the target firm must be estimated by the purchasing company in order to determine the acquisition premium.\nEnterprise value or equity valuation are both viable options to calculate the true worth of the target firm.\nA **transaction’s acquisition premium** may be estimated by dividing the difference between the amount per share spent by the purchasing company and the target company’s existing cost per share by the cost per share of the target firm at the time of the deal.\n**\nAcquisition premium or takeover premium = (amount per share spent by the purchasing - target company existing cost per share) / target company existing cost per share\n**",
            "title": "What is Acquisition Premium? | Eqvista",
            "url": "https://eqvista.com/company-valuation/m-a-valuation-methods/acquisition-premium/",
            "date": "2026-03-24",
            "last_updated": "2026-05-16",
            "source": "web"
          },
          {
            "id": 5,
            "snippet": "A strategic buyer is a company that acquires another business to strengthen its market position or capabilities.\nUnlike financial buyers, who prioritize investment returns, strategic buyers focus on how the acquired company fits into their long-term business strategy.\nThe goal is expansion, efficiency, or synergy that gives them a competitive edge.\n...\nStrategic buyers often pay more when integration creates value through cost savings, better purchasing, or expanded revenue.\nThat premium is not always tied to your current performance.\nStrategic buyers value your business based on what it becomes once integrated into their existing operations.\n...\nA financial buyer is an investor who acquires a business to generate a return.\nThese buyers include private equity firms, family offices, investment groups, and independent sponsors.\nThey plan to grow the company’s value and exit later through resale or recapitalization.",
            "title": "Financial Buyer vs Strategic Buyer: Key Differences When Selling a ...",
            "url": "https://advisorlegacy.com/blog/strategic-vs-financial-buyers",
            "date": "2026-01-09",
            "last_updated": "2026-05-16",
            "source": "web"
          },
          {
            "id": 6,
            "snippet": "In mergers and acquisitions, some buyers are willing to pay more than standard valuation multiples when a target company creates unique strategic value.\nThis is known as the **“strategic fit premium.”** Strategic buyers may offer higher valuations when an acquisition strengthens market position, accelerates growth, creates operational synergies, or eliminates competitive threats.\n...\nIn many transactions, buyers are willing to pay **above market valuation** when the acquisition creates strategic advantages that extend beyond the company’s standalone financial performance.\n...\nStrategic fit refers to how well a target company aligns with a buyer’s broader business strategy.\n...\n**What is a strategic premium in M&A?**\nA strategic premium occurs when a buyer pays more than typical valuation multiples because the acquisition creates additional value beyond the target company’s stand-alone financial performance.",
            "title": "Why Strategic Buyers Sometimes Pay More Than Market Valuation",
            "url": "https://horizonmaa.com/insights/why-strategic-buyers-sometimes-pay-more-than-market-valuation/",
            "date": "2026-03-26",
            "last_updated": "2026-03-26",
            "source": "web"
          },
          {
            "id": 7,
            "snippet": "The acquisition premium, also known as the takeover premium, is the difference between the actual price paid for a target company during a merger or acquisition based on its pre-merger value.\nA premium is commonly paid if the acquirer has identified potential synergies resulting from the transaction that will offset the cost of the premium paid.\n...\nThe takeover premium (acquisition premium) formula is calculated by subtracting the value before merger from the total amount paid by the acquirer.\nHere is the formula\n**TP = ** Amount Paid – Pre Merger Value\n**Where:**\n**Amount Paid:** The total cost of purchasing or merging with the target company.\nIt can be expressed in terms of the equity value of the transaction or the full value paid for both the company’s equity and debt.\n**Pre-Merger Value:** The market value of the firm before the transaction was brought.\n...\nAn acquisition takeover premium refers to the extra amount an acquiring company pays over the current market value of the target company’s shares to purchase and gain control of it.\n...\nThe takeover premium is calculated by subtracting the target company’s stock price before the acquisition announcement from the offer price, then dividing by the pre-announcement stock price and multiplying by 100 to get a percentage.",
            "title": "Acquisition Premium (Takeover) | Definition & Example Calculation",
            "url": "https://www.myaccountingcourse.com/acquisition-premium-takeover",
            "date": "2024-03-04",
            "last_updated": "2026-04-30",
            "source": "web"
          },
          {
            "id": 8,
            "snippet": "When the strategic rationale is strong, buyers may be willing to pay a premium.",
            "title": "How Strategic and Financial Buyers Differ in Software M&A",
            "url": "https://softwareequity.com/blog/financial-vs-strategic-buyers",
            "date": "2026-04-08",
            "last_updated": "2026-04-18",
            "source": "web"
          },
          {
            "id": 9,
            "snippet": "Synergies are often described as situations where “the whole is greater than the sum of its parts.”\nIn corporate M&A, a synergy is generated when a merged company is more valuable than the two separate companies.\n...\nThe amount that a strategic buyer is willing to pay for the synergies is known as the synergy premium.\nSynergy premium is calculated by taking the present value of future synergy benefits generated in the merged entity.\n...\nThe $20.5 million difference in net present value calculated by the strategic buyer compared with the financial buyer is the synergy premium.\nThis amount is equal to the net present value of the after-tax cost synergies.",
            "title": "How Synergies Impact What a Strategic Buyer Will Pay",
            "url": "https://www.pcecompanies.com/resources/how-synergies-impact-what-buyers-pay",
            "date": "2020-08-07",
            "last_updated": "2026-03-08",
            "source": "web"
          },
          {
            "id": 10,
            "snippet": "A **“purchase premium”** in the context of mergers and acquisitions refers to the excess that an acquirer pays over the market trading value of the shares being acquired.\n**“Premiums Paid Analysis”** is the name of a common investment banking analysis that reviews comparable transactions and averages the premiums paid for those transactions.",
            "title": "Premiums Paid Analysis | M&A Calculation Example - Wall Street Prep",
            "url": "https://www.wallstreetprep.com/knowledge/premiums-in-ma/",
            "date": "2023-12-05",
            "last_updated": "2026-05-17",
            "source": "web"
          },
          {
            "id": 11,
            "snippet": "Often, strategic buyers are willing to pay more for companies than financial buyers.\nOne reason is that a strategic buyer is better placed to realize synergistic benefits almost instantly.\nThis is because of the economies of scale that may arise from integrated operations.\nThe more the acquired business fits into the existing company’s structure, the more a strategic buyer will want the business and the higher the premium he will be willing to pay.",
            "title": "Strategic v. Financial Buyer: Tutorial and Video - Noble Desktop Blog",
            "url": "https://blog.nobledesktop.com/learn/financial-modeling/strategic-financial-buyer",
            "date": "2026-04-19",
            "last_updated": "2026-04-21",
            "source": "web"
          },
          {
            "id": 12,
            "snippet": "An acquisition premium is the difference (excess) between the market value of a company and the price paid to acquire it.\nAn acquisition premium represents the increased cost of buying a target company during a merger and acquisition (M&A) transaction.\n...\nNo specific definition exists for acquisition premium, which could reflect the value of both control and synergies.\nOur study is based on all transactions irrespective of the percentage acquired.",
            "title": "An analysis of acquisition premiums in Australia from 2012 to 2022",
            "url": "https://www.findex.com.au/insights/article/acquisition-premium-study-an-analysis-of-acquisition-premiums-in-australia-from-2012-to-2022",
            "date": "2023-03-06",
            "last_updated": "2026-05-19",
            "source": "web"
          },
          {
            "id": 13,
            "snippet": "In the absence of a sufficient control premium, it is unlikely for an acquirer to successfully obtain a majority stake in the target.\nTherefore, a reasonable premium is paid over the current share price in practically all acquisitions.\n**The control premium normally ranges from around 25% to 30%, but it can vary substantially from deal-to-deal and be as high as 50% above the target’s share price.**",
            "title": "Control Premium | Formula + Calculator - Wall Street Prep",
            "url": "https://www.wallstreetprep.com/knowledge/control-premium/",
            "date": "2023-10-12",
            "last_updated": "2026-05-20",
            "source": "web"
          }
        ],
        "type": "search_results",
        "queries": [
          "acquisition premium definition M&A",
          "difference strategic vs financial buyers approach to acquisition premium",
          "determinants of acquisition premium strategic buyers synergies"
        ]
      },
      {
        "id": "msg_96e89ec9-5a54-43d4-a4b7-658166b59734",
        "content": [
          {
            "text": "An acquisition premium is the excess an acquirer pays over the target’s standalone market or fair value—often reflected as goodwill on the acquirer’s balance sheet. [web:1][web:4][web:7][web:12] Strategic buyers usually justify and pay higher premiums due to synergies and strategic fit, while financial buyers are more constrained by return thresholds and typical market valuations. [web:2][web:3][web:5][web:9][web:11]\n\n## What is an acquisition premium?\n\n- An acquisition (or takeover) premium is the difference between the price paid for a target company and its pre‑deal market or fair value. [web:1][web:4][web:7][web:12]  \n- It is typically measured as a percentage over the target’s unaffected share price before the deal is announced and is recorded as **goodwill** (an intangible asset) on the buyer’s balance sheet. [web:1][web:4][web:7][web:10]\n\n## Why do buyers pay a premium?\n\n- Premiums compensate target shareholders for giving up control and future upside; many control transactions show premiums in the ~20–30% range, though this varies by deal. [web:10][web:13]  \n- Buyers pay premiums when they expect value from synergies (cost savings, revenue growth, tax or financing benefits) that makes the combined business worth more than the sum of the parts. [web:3][web:7][web:9]\n\n## Strategic buyers’ approach\n\nStrategic buyers are operating companies acquiring to enhance their existing business.\n\n- They value the target based on strategic synergies: cost savings, cross‑selling, technology or capability gaps, and stronger market position, often leading them to pay a **strategic** or synergy premium. [web:2][web:5][web:6][web:9]  \n- Because they can often realize synergies quickly (economies of scale, overlapping SG&A, better purchasing power), they are frequently willing to pay higher premiums than financial buyers for the same asset. [web:2][web:5][web:8][web:11]\n\n## Financial buyers’ approach\n\nFinancial buyers (e.g., private equity, investment funds) focus on returns from buying, improving, and later exiting the investment.\n\n- They typically value the target on standalone cash flows and metrics such as EBITDA, applying market multiples and disciplined return (IRR/MOIC) hurdles, which limits how much premium they can pay. [web:2][web:5][web:8]  \n- Because they usually cannot realize large operating synergies themselves, they are less inclined to pay high premiums unless there is an exceptional growth or operational improvement story that still meets their return targets. [web:2][web:3][web:5][web:9]\n\n## Typical pattern: who pays more?\n\n- Empirical and practitioner evidence indicates that strategically motivated acquisitions tend to feature higher premiums than financially motivated or purely conglomerate deals, as strategic synergies usually support larger incremental value. [web:3][web:6][web:11]  \n- In competitive auctions, strategic buyers often outbid financial buyers when the asset has strong strategic fit, because the additional synergy value allows them to justify a higher acquisition premium while still creating shareholder value. [web:2][web:5][web:9][web:11]",
            "type": "output_text",
            "annotations": [],
            "logprobs": []
          }
        ],
        "role": "assistant",
        "status": "completed",
        "type": "message"
      }
    ],
    "status": "completed",
    "error": null,
    "usage": {
      "input_tokens": 7230,
      "output_tokens": 762,
      "total_tokens": 7992,
      "cost": {
        "currency": "USD",
        "input_cost": 0.00456,
        "output_cost": 0.00762,
        "total_cost": 0.01763,
        "cache_creation_cost": null,
        "cache_read_cost": 0.00045,
        "tool_calls_cost": 0.005
      },
      "input_tokens_details": {
        "cache_creation_input_tokens": 0,
        "cache_read_input_tokens": 3584,
        "cached_tokens": 3584
      },
      "tool_calls_details": {
        "search_web": {
          "invocation": 1
        }
      },
      "output_tokens_details": {
        "reasoning_tokens": 0
      }
    },
    "background": false,
    "completed_at": 1779391825,
    "frequency_penalty": 0,
    "incomplete_details": null,
    "instructions": "## Abstract\n<role>\nYou are an AI assistant developed by Perplexity AI. Given a user's query, your goal is to generate an expert, useful, factually correct, and contextually relevant response by leveraging available tools and conversation history. First, you will receive the tools you can call iteratively to gather the necessary knowledge for your response. You need to use these tools rather than using internal knowledge. Second, you will receive guidelines to format your response for clear and effective presentation. Third, you will receive guidelines for citation practices to maintain factual accuracy and credibility.\n</role>\n\n## Instructions\n<tools_workflow>\nBegin each turn with tool calls to gather information. You must call at least one tool before answering, even if information exists in your knowledge base. Decompose complex user queries into discrete tool calls for accuracy and parallelization. After each tool call, assess if your output fully addresses the query and its subcomponents. Continue until the user query is resolved or until the <tool_call_limit> below is reached. End your turn with a comprehensive response. Never mention tool calls in your final response as it would badly impact user experience.\n\n<tool_call_limit> Make at most three tool calls before concluding.</tool_call_limit>\n</tools_workflow>\n\n## Citation Instructions\n<citation_instructions>\nYour response must include at least 1 citation. Add a citation to every sentence that includes information derived from tool outputs.\nTool results are provided using `id` in the format `type:index`. `type` is the data source or context. `index` is the unique identifier per citation.\n<common_source_types> are included below.\n\n<common_source_types>\n- `web`: Internet sources\n- `page`: Full web page content\n- `conversation_history`: past queries and answers from your interaction with the user\n</common_source_types>\n\n<formatting_citations>\nUse brackets to indicate citations like this: [type:index]. Commas, dashes, or alternate formats are not valid citation formats. If citing multiple sources, write each citation in a separate bracket like [web:1][web:2][web:3].\n\nCorrect: \"The Eiffel Tower is in Paris [web:3].\"\nIncorrect: \"The Eiffel Tower is in Paris [web-3].\"\n</formatting_citations>\n\nYour citations must be inline - not in a separate References or Citations section. Cite the source immediately after each sentence containing referenced information. If your response presents a markdown table with referenced information from `web`, `memory`, `attached_file`, or `calendar_event` tool result, cite appropriately within table cells directly after relevant data instead in of a new column. Do not cite `generated_image` or `generated_video` inside table cells.\n\n## Response Guidelines\n<response_guidelines>\nResponses are displayed on web interfaces where users should not need to scroll extensively. Limit responses to 5 sections maximum. Users can ask follow-up questions if they need additional detail. Prioritize the most relevant information for the initial query.\n\n### Answer Formatting\n- Begin with a direct 1-2 sentence answer to the core question.\n- Organize the rest of your answer into sections led with Markdown headers (using ##, ###) when appropriate to ensure clarity (e.g. entity definitions, biographies, and wikis).\n- Your answer should be at least 3 sentences long.\n- Each Markdown header should be concise (less than 6 words) and meaningful.\n- Markdown headers should be plain text, not numbered.\n- Between each Markdown header is a section consisting of 2-3 well-cited sentences.\n- When comparing entities with multiple dimensions, use a markdown table to show differences (instead of lists).\n- Whenever possible, present information as bullet point lists to improve readability.\n- You are allowed to bold at most one word (**example**) per paragraph. You can't bold consecutive words.\n- For grouping multiple related items, present the information with a mix of paragraphs and bullet point lists. Do not nest lists within other lists.\n\n### Tone\n<tone>\nExplain clearly using plain language. Use active voice and vary sentence structure to sound natural. Ensure smooth transitions between sentences. Avoid personal pronouns like \"I\". Keep explanations direct; use examples or metaphors only when they meaningfully clarify complex concepts that would otherwise be unclear.\n</tone>\n\n### Lists and Paragraphs\n<lists_and_paragraphs>\nUse lists for: multiple facts/recommendations, steps, features/benefits, comparisons, or biographical information.\n\nAvoid repeating content in both intro paragraphs and list items. Keep intros minimal. Either start directly with a header and list, or provide 1 sentence of context only.\n\nList formatting:\n- Use numbers when sequence matters; otherwise bullets (-) with a space after the dash.\n- Use numbers when sequence matters; otherwise bullets (-).\n- No whitespace before bullets (i.e. no indenting), one item per line.\n- Sentence capitalization; periods only for complete sentences.\n\nParagraphs:\n- Use for brief context (2-3 sentences max) or simple answers\n- Separate with blank lines\n- If exceeding 3 consecutive sentences, consider restructuring as a list\n</lists_and_paragraphs>\n\n### Summaries and Conclusions\n<summaries_and_conclusions>\nAvoid summaries and conclusions. They are not needed and are repetitive. Markdown tables are not for summaries. For comparisons, provide a table to compare, but avoid labeling it as 'Comparison/Key Table', provide a more meaningful title.\n</summaries_and_conclusions>\n\n## Prohibited Meta-Commentary\n<prohibited_commentary>\n- Never reference your information gathering process in your final answer.\n- Do not use phrases such as:\n- \"Based on my search results...\"\n- \"Now I have gathered comprehensive information...\"\n- \"According to my research...\"\n- \"My search revealed...\"\n- \"I found information about...\"\n- \"Let me provide a detailed answer...\"\n- \"Let me compile this information...\"\n- \"Short Answer: ...\"\n- Begin answers immediately with factual content that directly addresses the user's query.\n</prohibited_commentary>\n\n<copyright_requirements>\n- Never reproduce copyrighted content (text, lyrics, etc.)\n- You may share public domain content (expired copyrights, traditional works)\n- When copyright status is uncertain, treat as copyrighted\n- Keep summaries brief (under 30 words) and original — don't reconstruct sources\n- Brief factual statements (names, dates, facts) are always acceptable\n</copyright_requirements>\n\nCurrent date: Thursday, May 21, 2026\n\n",
    "max_output_tokens": 8192,
    "max_tool_calls": null,
    "metadata": {},
    "parallel_tool_calls": true,
    "presence_penalty": 0,
    "previous_response_id": null,
    "prompt_cache_key": null,
    "reasoning": null,
    "safety_identifier": null,
    "service_tier": "default",
    "store": true,
    "temperature": 1,
    "text": {
      "format": {
        "type": "text"
      }
    },
    "tool_choice": "auto",
    "tools": [
      {
        "type": "web_search"
      },
      {
        "type": "fetch_url"
      }
    ],
    "top_logprobs": 0,
    "top_p": 1,
    "truncation": "disabled",
    "user": null
  }
  ```
</Accordion>

## API Compatibility

### Standard OpenAI Parameters

These parameters work exactly the same as OpenAI's API:

**Agent API:**

* `model` - Model name (use 3rd party models like `openai/gpt-5.5`)
* `input` - Input text or message array
* `instructions` - System instructions
* `max_output_tokens` - Maximum tokens in response
* `stream` - Enable streaming responses
* `tools` - Array of tools including `web_search`

### Perplexity-Specific Parameters

**Agent API:**

* `preset` - Preset name (use Perplexity presets like `pro-search`)
* `tools[].filters` - Search filters within web\_search tool
* `tools[].user_location` - User location for localized results

<Info>
  See [Agent API Reference](/api-reference/agent-post) for complete parameter details.
</Info>

## Endpoint Mapping

| Method                      | Perplexity Endpoint | OpenAI Equivalent    | Notes                                                         |
| --------------------------- | ------------------- | -------------------- | ------------------------------------------------------------- |
| `client.responses.create()` | `POST /v1/agent`    | `POST /v1/responses` | Both paths accepted by Perplexity for compatibility           |
| `client.models.list()`      | `GET /v1/models`    | `GET /v1/models`     | Lists available Agent API models. No authentication required. |

<Info>
  When using the OpenAI SDK, `client.responses.create()` sends requests to `/v1/responses`. Perplexity accepts this path as an alias for `/v1/agent`, so no SDK configuration changes are needed beyond `base_url`.
</Info>

### Model Discovery

The `GET /v1/models` endpoint returns all models available for the Agent API in OpenAI-compatible format. No authentication is required.

<Tabs>
  <Tab title="Python">
    ```python theme={null}
    import os
    from openai import OpenAI

    client = OpenAI(
        api_key=os.environ.get("PERPLEXITY_API_KEY"),
        base_url="https://api.perplexity.ai/v1"
    )

    models = client.models.list()
    for model in models.data:
        print(f"{model.id} (owned by {model.owned_by})")
    ```
  </Tab>

  <Tab title="Typescript">
    ```typescript theme={null}
    import OpenAI from 'openai';

    const client = new OpenAI({
      apiKey: process.env.PERPLEXITY_API_KEY,
      baseURL: "https://api.perplexity.ai/v1"
    });

    const models = await client.models.list();
    for (const model of models.data) {
      console.log(`${model.id} (owned by ${model.owned_by})`);
    }
    ```
  </Tab>

  <Tab title="cURL">
    ```bash theme={null}
    curl https://api.perplexity.ai/v1/models
    ```
  </Tab>
</Tabs>

<Tip>
  This endpoint is compatible with tools like [Open WebUI](https://openwebui.com/), [Cherry Studio](https://cherry-ai.com/), and [LiteLLM](https://litellm.ai/) that auto-discover available models via the OpenAI `/v1/models` endpoint.
</Tip>

## Response Structure

### Agent API

Perplexity's Agent API matches OpenAI's Responses API response format:

* `output` - Structured output array containing messages with `content[].text`
* `model` - The model name used
* `usage` - Token consumption details
* `id`, `created_at`, `status` - Response metadata

## Best Practices

<Steps>
  <Step title="Use the correct base URL">
    Always use `https://api.perplexity.ai/v1` (with `/v1`) for the Agent API.

    ```python theme={null}
    client = OpenAI(
        api_key=os.environ.get("PERPLEXITY_API_KEY"),
        base_url="https://api.perplexity.ai/v1"  # Correct
    )
    ```
  </Step>

  <Step title="Handle errors gracefully">
    Use the OpenAI SDK's error handling:

    ```python theme={null}
    import os
    from openai import OpenAI, APIError, RateLimitError

    client = OpenAI(
        api_key=os.environ.get("PERPLEXITY_API_KEY"),
        base_url="https://api.perplexity.ai/v1"
    )

    try:
        response = client.responses.create(
            model="openai/gpt-5.5",
            input="Hello"
        )
    except RateLimitError:
        print("Rate limit exceeded, please retry later")
    except APIError as e:
        print(f"API error: {e.message}")
    ```
  </Step>

  <Step title="Use streaming for better UX">
    Stream responses for real-time user experience:

    ```python theme={null}
    response = client.responses.create(
        model="openai/gpt-5.5",
        input="Long query...",
        stream=True
    )

    for event in response:
        if event.type == "response.output_text.delta":
            print(event.delta, end="", flush=True)
    ```
  </Step>
</Steps>

## Recommended: Perplexity SDK

We recommend using Perplexity's native SDKs for the best developer experience:

* **Cleaner preset syntax** - Use `preset="pro-search"` directly instead of `extra_body={"preset": "pro-search"}`
* **Type safety** - Full Typescript/Python type definitions for all parameters
* **Enhanced features** - Direct access to all Perplexity-specific features
* **Better error messages** - Perplexity-specific error handling
* **Simpler setup** - No need to configure base URLs

See the [Perplexity SDK Guide](/docs/sdk/overview) for details.

## Migrating to the Perplexity SDK

Switch to the Perplexity SDK for enhanced features and cleaner syntax. With the Perplexity SDK, you can use presets directly without `extra_body` and get full type safety:

<Steps>
  <Step title="Install the Perplexity SDK">
    <Tabs>
      <Tab title="Python">
        ```bash theme={null}
        pip install perplexityai
        ```
      </Tab>

      <Tab title="Typescript">
        ```bash theme={null}
        npm install @perplexity-ai/perplexity_ai
        ```
      </Tab>
    </Tabs>
  </Step>

  <Step title="Update the import and client">
    <Tabs>
      <Tab title="Python">
        ```python theme={null}
        # Before (OpenAI SDK)
        import os
        from openai import OpenAI
        client = OpenAI(
            api_key=os.environ.get("PERPLEXITY_API_KEY"),
            base_url="https://api.perplexity.ai/v1"
        )

        # After (Perplexity SDK)
        from perplexity import Perplexity
        client = Perplexity()  # reads PERPLEXITY_API_KEY env var automatically
        ```
      </Tab>

      <Tab title="Typescript">
        ```typescript theme={null}
        // Before (OpenAI SDK)
        import OpenAI from 'openai';
        const openaiClient = new OpenAI({
          apiKey: process.env.PERPLEXITY_API_KEY,
          baseURL: "https://api.perplexity.ai/v1"
        });

        // After (Perplexity SDK)
        import Perplexity from '@perplexity-ai/perplexity_ai';
        const perplexityClient = new Perplexity();  // reads PERPLEXITY_API_KEY env var automatically
        ```
      </Tab>
    </Tabs>

    <Info>
      **No base URL needed** - The Perplexity SDK automatically uses the correct endpoint.
    </Info>
  </Step>

  <Step title="Update the API calls">
    The API calls are very similar:

    <Tabs>
      <Tab title="Python">
        ```python theme={null}
        # Agent API - same interface
        response = client.responses.create(
            model="openai/gpt-5.5",
            input="Hello!"
        )
        ```
      </Tab>

      <Tab title="Typescript">
        ```typescript theme={null}
        // Agent API - same interface
        const response = await client.responses.create({
          model: "openai/gpt-5-mini",
          input: "Hello!"
        });
        ```
      </Tab>
    </Tabs>
  </Step>

  <Step title="Use presets with cleaner syntax">
    The Perplexity SDK supports presets with cleaner syntax compared to OpenAI SDK:

    <Tabs>
      <Tab title="Python">
        ```python theme={null}
        # Before (OpenAI SDK) - extra_body required
        response = client.responses.create(
            input="What is the difference between an IPO and a direct listing, and why did Coinbase choose a direct listing for its 2021 public debut?",
            extra_body={"preset": "pro-search"}
        )

        # After (Perplexity SDK) - direct parameter
        response = client.responses.create(
            preset="pro-search",
            input="What is the difference between an IPO and a direct listing, and why did Coinbase choose a direct listing for its 2021 public debut?"
        )
        ```
      </Tab>

      <Tab title="Typescript">
        ```typescript theme={null}
        // Before (OpenAI SDK) - type casting required
        const response = await client.responses.create({
          input: "What is the difference between an IPO and a direct listing, and why did Coinbase choose a direct listing for its 2021 public debut?",
          preset: "pro-search"
        } as any);

        // After (Perplexity SDK) - fully typed
        const response = await client.responses.create({
          preset: "pro-search",
          input: "What is the difference between an IPO and a direct listing, and why did Coinbase choose a direct listing for its 2021 public debut?"
        });
        ```
      </Tab>
    </Tabs>

    <Accordion title="Response">
      ```json theme={null}
      {
        "id": "resp_532010e6-2d26-4159-b54b-932e9f553b43",
        "created_at": 1779391925,
        "model": "openai/gpt-5.1",
        "object": "response",
        "output": [
          {
            "results": [
              {
                "id": 1,
                "snippet": "A direct listing allows a company to enter the public market by listing existing shares without issuing new ones.\nUnlike an IPO, there are no underwriters to set the initial share price or facilitate new capital raising.\nInstead, the market determines the share price based on supply and demand.\nDirect listings do not create or sell new shares, meaning no capital is raised through the listing itself.\nThe company avoids hefty underwriter fees, leading to potential cost savings.\nExisting shareholders gain immediate liquidity, as there are no traditional IPO lockup periods.\nPrice discovery is entirely market-driven rather than being set by investment banks.\nThe direct listing process is thorough.\nFirst, the company prepares financial statements and ensures compliance with public company requirements.\nThen, it submits a registration statement to the SEC for direct listings, detailing financial health and risk factors.\nUnlike an IPO, where banks allocate shares, direct listings allow shares to trade freely once listed.\nThe share price is set by market supply and demand rather than pre-determined underwriting.\n...\nIPOs raise new capital through the issuance of additional shares, providing the company with funds for growth, expansion, and operational needs.\nDirect listings, on the other hand, do not raise capital since no new shares are issued.\n...\nChoosing between an IPO and a direct listing depends on a company’s capital needs, market positioning, and strategic goals.\nIPOs provide structured price setting, capital infusion, and investor support but come with higher costs.\nDirect listings offer cost efficiency and liquidity but require market-driven pricing and strong brand recognition.",
                "title": "IPO vs Direct Listing | DFIN",
                "url": "https://www.dfinsolutions.com/knowledge-hub/thought-leadership/knowledge-resources/ipo-vs-direct-listing",
                "date": "2025-02-20",
                "last_updated": "2026-05-11",
                "source": "web"
              },
              {
                "id": 2,
                "snippet": "- The company went public through a direct listing, which means it sold its shares to the public without the usual middlemen, such as investment banks and other underwriters, that typically help with a traditional IPO.\n...\nA direct listing—sometimes called a direct offering—is a way for a company to sell its shares to the public without involving any middle men, or intermediaries.\nIt’s different from an initial public offering (IPO), where the company relies on an investment bank to take it public.\nSuch a bank is called an “underwriter,” because it assumes much of the risk associated with the IPO.\nWith a direct listing, company executives, early investors, and employees who own equity, or shares, are given the option to convert them into a public stock and then sell it to the public through a stock exchange such as the New York Stock Exchange or the Nasdaq.\n(These stakeholders are not obligated to sell their shares, however.)\nWith a direct listing, the stock exchange sets the starting trading price.\nIt’s called an “initial reference price,” and it’s based on new investor demand for the shares.\nIn contrast, the underwriters set what’s known as an “opening price” in a traditional IPO, through a process called a roadshow.",
                "title": "Highlights from Coinbase's IPO - Stash",
                "url": "https://www.stash.com/learn/highlights-from-coinbases-ipo/",
                "date": "2021-04-16",
                "last_updated": "2026-04-08",
                "source": "web"
              },
              {
                "id": 3,
                "snippet": "A private company raises capital by selling newly-issued shares to investment banks (underwriters), which the banks \nthen sell primarily to institutional investors.\n...\nDirect Listing\n...\nA private company becomes public, typically without raising new funds in the process, by allowing existing shareholders \nto sell shares directly to the public.",
                "title": "[PDF] What are the differences in an IPO, a SPAC, and a direct listing?",
                "url": "https://www.sec.gov/files/registered-offerings-building-blocks.pdf",
                "date": null,
                "last_updated": "2024-09-22",
                "source": "web"
              },
              {
                "id": 4,
                "snippet": "Coinbase followed the footsteps of Spotify and Palantir by choosing to go public via a direct listing where existing investors make their shares available for sale to the public, as opposed to a traditional IPO run by investment banks.",
                "title": "Coinbase's IPO - MergerSight",
                "url": "https://www.mergersight.com/post/coinbase-s-ipo",
                "date": "2021-05-06",
                "last_updated": "2026-05-15",
                "source": "web"
              },
              {
                "id": 5,
                "snippet": "**Direct Listing** is the process by which a company goes public by getting listed on an exchange and offering existing shares directly to the open market.\n...\nThe traditional initial public offering (IPO) model has been disrupted by the emergence of direct listings, in which a company starts selling shares directly to the public.\nThe direct listing process is straightforward, as the company’s shares begin trading on an exchange, with no shares pre-negotiated and sold to institutional investors at a designated price.\nCompanies that opt for the direct listing route tend to be already well-funded (i.e. backed by more than enough capital) – therefore, there is no need for these companies to raise further capital through an IPO.\n...\nBut at the end of the day, direct listings and IPOs achieve the same objectives:\n...\n- **Institutional and Retail Investors**→ Equity Ownership Shifts from Insiders (e.g. Management, Employees, Venture Capital Firms, Growth Equity Firms) to the Broader Institutional and Retail Market\n...\nCompanies may choose to go public via a direct listing due to:\n- **Anti-Dilution**– For companies with enough capital and just seeking to get listed, the direct listing route avoids the issuance of new shares (and dilution to existing shareholders)\n- **Immediate Liquidity**– In the traditional IPO, there is a 180-day lock-up period for shareholders before shares can be sold, but in a direct listing, existing shareholders can sell their stake starting on the first day of trading\n- **Supply/Demand Structure**– Rather than establishing a fixed pricing range as done in an IPO, a direct listing resembles an unrestricted auction where the market truly sets the price\nSignificant amounts of money are also saved in a direct listing by not having to pay IPO fees to investment banks – in part due to the shorter, more efficient process.\n...\nThe dilutive impact is kept to a minimum in a direct listing, since no new capital is raised – albeit new regulations have changed the rules regarding new capital raising.\n...\nIn traditional IPOs, the share price is pre-negotiated upon gauging investor appetite before the company goes public.\nBy contrast, direct listings are priced solely on supply and demand on the date of listing – i.e. resulting in an unpredictable reaction and more volatility.",
                "title": "Direct Listing vs. IPO | Difference + Examples - Wall Street Prep",
                "url": "https://www.wallstreetprep.com/knowledge/direct-listing/",
                "date": "2023-10-27",
                "last_updated": "2026-05-20",
                "source": "web"
              },
              {
                "id": 6,
                "snippet": "An Initial Public Offering (IPO) refers to the process by which a private company offers newly issued shares to the public for the first time.\nIn an IPO, the company typically works with one or more underwriters, often investment banks, that assist with pricing, marketing, and distributing shares to investors.\nIPOs generally involve a structured pricing process, where the offering price is set before trading begins based on company financials, market conditions, and investor demand.\nShares are often allocated to institutional investors before becoming available to the broader public once trading starts on a public exchange.\n...\nA Direct Listing allows a company’s existing shares to begin trading on a public exchange without issuing new shares or relying on underwriters in the traditional IPO sense.\nInstead of raising new capital, the primary focus of a Direct Listing is generally on providing liquidity to existing shareholders, such as employees, founders, and early investors.\nIn a Direct Listing, the opening share price is typically determined by market supply and demand rather than being set in advance.\nBecause no new shares are issued, the company generally does not receive proceeds from initial trading activity.\n...\nNot necessarily.\nIPOs and SPAC transactions generally involve raising new capital, while Direct Listings primarily focus on enabling existing shareholders to sell shares without issuing new ones.",
                "title": "Direct Listing vs IPO vs SPAC Paths to the Public Markets...",
                "url": "https://www.startengine.com/blog/direct-listing-vs-ipo-vs-spac",
                "date": "2026-01-28",
                "last_updated": "2026-05-20",
                "source": "web"
              },
              {
                "id": 7,
                "snippet": "This means they simply listed what shares they have instead of issuing new shares via a typical IPO route.\n...\n{ts:157} you may have heard of an initial public offering before or an IPO this is where a company will create and issue new\n{ts:163} shares to the general public at a set price and in doing so raise a ton of cash for its operations however a\n...\n{ts:183} instead coinbase decided to proceed with a direct listing instead of an IPO this is where they simply take all the shares\n{ts:190} that are currently issued and put them on a public Stock Exchange in this case the NASDAQ Stock Exchange Founders and\n{ts:196} early investors can sell their holding and make an exit and new participants can buy shares in speculation that the",
                "title": "The Coinbase Direct Listing Explained - YouTube",
                "url": "https://www.youtube.com/watch?v=IGV-eSpcuck",
                "date": "2021-04-18",
                "last_updated": "2025-10-11",
                "source": "web"
              },
              {
                "id": 8,
                "snippet": "Coinbase, one of the largest cryptocurrency exchanges in the US, has announced plans to go public but it will eschew the traditional initial public offering process, opting instead for a direct listing.\n...\nAs Coinbase opted for a direct listing as opposed to an IPO, retail investors will need to wait for when shares can be publicly bought and sold in order to purchase stocks.",
                "title": "Blending Crypto and Stocks: What Does Coinbase Direct Listing Mean for Crypto Landscape? - Coinspeaker",
                "url": "https://www.coinspeaker.com/coinbase-listing-crypto-landscape/",
                "date": "2021-03-29",
                "last_updated": "2025-06-09",
                "source": "web"
              },
              {
                "id": 9,
                "snippet": "Also called a direct public offering or direct placement, a direct listing allows people who already hold shares to sell them directly.\nIn this model, companies don’t have to deal with (and pay) underwriters.\nIt also lets them avoid creating new shares and diluting ownership.\nThere are no intermediaries involved.^1^\n...\nThe main differences between an IPO and a direct listing include the underwriting process, pricing, and timing.\n...\nIn a direct listing, there are no underwriters involved.\nAn investment bank may provide advice, but it has a limited role.\nShareholders sell their stock directly to the public.^3^\n...\nWith an IPO, existing shares are usually locked up for 180 days.\nThis prevents insiders from selling their shares during this time.\nStocks are typically sold to investment banks initially.\nWith a direct listing, shares can be sold immediately.\nThere’s no lockup period, and existing shareholders have immediate liquidity.^3^\n...\nIPOs are more expensive than direct listings.\nUnderwriters charge a percentage of the gross sales, and there are additional expenses related to roadshows and publicity.",
                "title": "IPO vs Direct Listing: Understanding the Key Differences",
                "url": "https://onlinemba.ku.edu/experience-ku/mba-blog/ipo-vs-direct-listing",
                "date": "2024-12-11",
                "last_updated": "2026-03-16",
                "source": "web"
              },
              {
                "id": 10,
                "snippet": "The event was notable for several reasons: Coinbase, with 56 million registered users, became the first crypto company to list on a US stock exchange; it was also Nasdaq’s first major direct listing.\nThe firm sidestepped a typical IPO and the increasingly popular special purpose acquisition company (SPAC) as routes to the public.\nAs CEO Brian Armstrong told CNBC, “I wanted there to be just a true market on day one that set the price, not something that was set behind closed doors.”\nThe direct listing, which provides greater accessibility to retail investors, is also more “true to the [democratic] ethos of crypto,” he added.",
                "title": "Coinbase Direct Listing Steadies Crypto Industry",
                "url": "https://gfmag.com/features/coinbase-direct-listing-steadies-crypto-industry/",
                "date": "2021-05-05",
                "last_updated": "2025-10-29",
                "source": "web"
              },
              {
                "id": 11,
                "snippet": "A direct listing differs from an IPO in that a company lists its existing stock without hiring underwriters to \nsell new shares and raise fresh money.\n...\nDirect listings can also save companies on underwriting fees.\nRather than hire investment banks to \nmarket and price new shares, companies conducting direct listings hire financial advisers, who play a\nmore limited role of linking buyers and sellers of existing stock at agreed prices.",
                "title": "Coinbase's Public Listing Plans Shine Spotlight On Crypto",
                "url": "https://www.crowell.com/a/web/bUWLyhYZmLFmezj8hyV5QX/4Ttk1y/20210129-coinbases-public-listing-plans-shine-spotlight-on-crypto.pdf",
                "date": null,
                "last_updated": "2025-03-26",
                "source": "web"
              }
            ],
            "type": "search_results",
            "queries": [
              "IPO vs direct listing differences",
              "Coinbase direct listing 2021 reasons",
              "Coinbase why chose direct listing over IPO 2021"
            ]
          },
          {
            "id": "msg_0d1729b8-2a0e-47a4-97c1-b113b65f80db",
            "content": [
              {
                "text": "An IPO issues new shares through underwriters to raise capital at a predetermined offering price, while a direct listing simply lists existing shares for trading without raising new money or using traditional underwriters, letting the market set the price. [web:1][web:3][web:5] Coinbase chose a direct listing in 2021 because it did not need to raise capital, wanted market-driven price discovery aligned with crypto’s open-market ethos, and could save on IPO fees while giving existing shareholders immediate liquidity. [web:4][web:5][web:10][web:11]  \n\n## IPO vs direct listing  \n\n- In an **IPO**, a company typically sells newly issued shares to the public through investment banks that act as underwriters, which help set the offer price, market the deal, and allocate shares, and the company receives new capital from the proceeds. [web:3][web:6]  \n- In a **direct listing**, the company usually does not issue new shares; instead, existing shareholders (founders, employees, early investors) sell their shares directly on the exchange, and the company generally does not raise new funds in the process. [web:1][web:3][web:5][web:6]  \n\n- IPOs use underwriters who build a book of demand and set an offering price before trading begins, creating a more controlled pricing process. [web:1][web:5][web:6][web:9]  \n- Direct listings do not have traditional underwriting; the opening trading price is set by supply and demand on the exchange (often via a reference price) and can be more volatile and unpredictable. [web:1][web:2][web:5][web:6]  \n\n- IPOs are typically more expensive because underwriters charge a percentage of the offering and there are costs for roadshows and marketing. [web:1][web:5][web:9][web:11]  \n- Direct listings tend to be cheaper because there are no underwriting fees and banks act only as financial advisers with a more limited role. [web:1][web:5][web:9][web:11]  \n\n- In many IPOs, insiders face a lockup period (often around 180 days) before they can sell shares, limiting immediate liquidity. [web:1][web:6][web:9]  \n- In a direct listing, there is typically no lockup, so existing shareholders can sell on day one, providing immediate liquidity. [web:1][web:5][web:6][web:9]  \n\n## Why Coinbase chose direct listing  \n\n- Coinbase was already well funded and did not need to raise additional capital, which made a direct listing attractive since that mechanism focuses on listing and liquidity rather than fundraising. [web:4][web:5][web:11]  \n- A direct listing avoided dilution from issuing new shares, which helped preserve ownership percentages for existing investors and employees. [web:5][web:6][web:11]  \n\n- CEO Brian Armstrong stated that he wanted “a true market on day one” with a price set in the open market rather than “behind closed doors,” so a direct listing’s market-driven pricing fit this goal. [web:10]  \n- This approach was described as more in line with the **democratic** and open ethos of crypto markets, reinforcing Coinbase’s brand positioning in the digital-asset space. [web:10]  \n\n- By choosing a direct listing, Coinbase could save substantial underwriting fees compared with a traditional IPO while still achieving a major listing on Nasdaq. [web:5][web:11]  \n- The structure also gave early investors and employees immediate liquidity on listing day, which is a common reason high-profile tech and fintech firms such as Spotify and Palantir have used direct listings. [web:4][web:5]",
                "type": "output_text",
                "annotations": [],
                "logprobs": []
              }
            ],
            "role": "assistant",
            "status": "completed",
            "type": "message"
          }
        ],
        "status": "completed",
        "error": null,
        "usage": {
          "input_tokens": 6821,
          "output_tokens": 852,
          "total_tokens": 7673,
          "cost": {
            "currency": "USD",
            "input_cost": 0.00405,
            "output_cost": 0.00852,
            "total_cost": 0.01802,
            "cache_creation_cost": null,
            "cache_read_cost": 0.00045,
            "tool_calls_cost": 0.005
          },
          "input_tokens_details": {
            "cache_creation_input_tokens": 0,
            "cache_read_input_tokens": 3584,
            "cached_tokens": 3584
          },
          "tool_calls_details": {
            "search_web": {
              "invocation": 1
            }
          },
          "output_tokens_details": {
            "reasoning_tokens": 0
          }
        },
        "background": false,
        "completed_at": 1779391925,
        "frequency_penalty": 0,
        "incomplete_details": null,
        "instructions": "## Abstract\n<role>\nYou are an AI assistant developed by Perplexity AI. Given a user's query, your goal is to generate an expert, useful, factually correct, and contextually relevant response by leveraging available tools and conversation history. First, you will receive the tools you can call iteratively to gather the necessary knowledge for your response. You need to use these tools rather than using internal knowledge. Second, you will receive guidelines to format your response for clear and effective presentation. Third, you will receive guidelines for citation practices to maintain factual accuracy and credibility.\n</role>\n\n## Instructions\n<tools_workflow>\nBegin each turn with tool calls to gather information. You must call at least one tool before answering, even if information exists in your knowledge base. Decompose complex user queries into discrete tool calls for accuracy and parallelization. After each tool call, assess if your output fully addresses the query and its subcomponents. Continue until the user query is resolved or until the <tool_call_limit> below is reached. End your turn with a comprehensive response. Never mention tool calls in your final response as it would badly impact user experience.\n\n<tool_call_limit> Make at most three tool calls before concluding.</tool_call_limit>\n</tools_workflow>\n\n## Citation Instructions\n<citation_instructions>\nYour response must include at least 1 citation. Add a citation to every sentence that includes information derived from tool outputs.\nTool results are provided using `id` in the format `type:index`. `type` is the data source or context. `index` is the unique identifier per citation.\n<common_source_types> are included below.\n\n<common_source_types>\n- `web`: Internet sources\n- `page`: Full web page content\n- `conversation_history`: past queries and answers from your interaction with the user\n</common_source_types>\n\n<formatting_citations>\nUse brackets to indicate citations like this: [type:index]. Commas, dashes, or alternate formats are not valid citation formats. If citing multiple sources, write each citation in a separate bracket like [web:1][web:2][web:3].\n\nCorrect: \"The Eiffel Tower is in Paris [web:3].\"\nIncorrect: \"The Eiffel Tower is in Paris [web-3].\"\n</formatting_citations>\n\nYour citations must be inline - not in a separate References or Citations section. Cite the source immediately after each sentence containing referenced information. If your response presents a markdown table with referenced information from `web`, `memory`, `attached_file`, or `calendar_event` tool result, cite appropriately within table cells directly after relevant data instead in of a new column. Do not cite `generated_image` or `generated_video` inside table cells.\n\n## Response Guidelines\n<response_guidelines>\nResponses are displayed on web interfaces where users should not need to scroll extensively. Limit responses to 5 sections maximum. Users can ask follow-up questions if they need additional detail. Prioritize the most relevant information for the initial query.\n\n### Answer Formatting\n- Begin with a direct 1-2 sentence answer to the core question.\n- Organize the rest of your answer into sections led with Markdown headers (using ##, ###) when appropriate to ensure clarity (e.g. entity definitions, biographies, and wikis).\n- Your answer should be at least 3 sentences long.\n- Each Markdown header should be concise (less than 6 words) and meaningful.\n- Markdown headers should be plain text, not numbered.\n- Between each Markdown header is a section consisting of 2-3 well-cited sentences.\n- When comparing entities with multiple dimensions, use a markdown table to show differences (instead of lists).\n- Whenever possible, present information as bullet point lists to improve readability.\n- You are allowed to bold at most one word (**example**) per paragraph. You can't bold consecutive words.\n- For grouping multiple related items, present the information with a mix of paragraphs and bullet point lists. Do not nest lists within other lists.\n\n### Tone\n<tone>\nExplain clearly using plain language. Use active voice and vary sentence structure to sound natural. Ensure smooth transitions between sentences. Avoid personal pronouns like \"I\". Keep explanations direct; use examples or metaphors only when they meaningfully clarify complex concepts that would otherwise be unclear.\n</tone>\n\n### Lists and Paragraphs\n<lists_and_paragraphs>\nUse lists for: multiple facts/recommendations, steps, features/benefits, comparisons, or biographical information.\n\nAvoid repeating content in both intro paragraphs and list items. Keep intros minimal. Either start directly with a header and list, or provide 1 sentence of context only.\n\nList formatting:\n- Use numbers when sequence matters; otherwise bullets (-) with a space after the dash.\n- Use numbers when sequence matters; otherwise bullets (-).\n- No whitespace before bullets (i.e. no indenting), one item per line.\n- Sentence capitalization; periods only for complete sentences.\n\nParagraphs:\n- Use for brief context (2-3 sentences max) or simple answers\n- Separate with blank lines\n- If exceeding 3 consecutive sentences, consider restructuring as a list\n</lists_and_paragraphs>\n\n### Summaries and Conclusions\n<summaries_and_conclusions>\nAvoid summaries and conclusions. They are not needed and are repetitive. Markdown tables are not for summaries. For comparisons, provide a table to compare, but avoid labeling it as 'Comparison/Key Table', provide a more meaningful title.\n</summaries_and_conclusions>\n\n## Prohibited Meta-Commentary\n<prohibited_commentary>\n- Never reference your information gathering process in your final answer.\n- Do not use phrases such as:\n- \"Based on my search results...\"\n- \"Now I have gathered comprehensive information...\"\n- \"According to my research...\"\n- \"My search revealed...\"\n- \"I found information about...\"\n- \"Let me provide a detailed answer...\"\n- \"Let me compile this information...\"\n- \"Short Answer: ...\"\n- Begin answers immediately with factual content that directly addresses the user's query.\n</prohibited_commentary>\n\n<copyright_requirements>\n- Never reproduce copyrighted content (text, lyrics, etc.)\n- You may share public domain content (expired copyrights, traditional works)\n- When copyright status is uncertain, treat as copyrighted\n- Keep summaries brief (under 30 words) and original — don't reconstruct sources\n- Brief factual statements (names, dates, facts) are always acceptable\n</copyright_requirements>\n\nCurrent date: Thursday, May 21, 2026\n\n",
        "max_output_tokens": 8192,
        "max_tool_calls": null,
        "metadata": {},
        "parallel_tool_calls": true,
        "presence_penalty": 0,
        "previous_response_id": null,
        "prompt_cache_key": null,
        "reasoning": null,
        "safety_identifier": null,
        "service_tier": "default",
        "store": true,
        "temperature": 1,
        "text": {
          "format": {
            "type": "text"
          }
        },
        "tool_choice": "auto",
        "tools": [
          {
            "type": "web_search"
          },
          {
            "type": "fetch_url"
          }
        ],
        "top_logprobs": 0,
        "top_p": 1,
        "truncation": "disabled",
        "user": null
      }
      ```
    </Accordion>
  </Step>
</Steps>

## Next Steps

<CardGroup>
  <Card title="Agent API Quickstart" icon="rocket" href="/docs/agent-api/quickstart">
    Get started with Agent API using OpenAI SDKs.
  </Card>

  <Card title="Agent API Models" icon="brain" href="/docs/agent-api/models">
    Explore direct model selection and third-party models.
  </Card>

  <Card title="API Reference" icon="code-circle" href="/api-reference/agent-post">
    View complete endpoint documentation.
  </Card>

  <Card title="Output Control" icon="indent-decrease" href="/docs/agent-api/output-control">
    Configure streaming responses and structured outputs with JSON schema.
  </Card>

  <Card title="Model Fallback" icon="square-rounded-arrow-down" href="/docs/agent-api/model-fallback">
    Specify multiple models for automatic failover and higher availability.
  </Card>

  <Card title="Filters" icon="filter" href="/docs/agent-api/tools/web-search#filters">
    Apply filters to web search results.
  </Card>
</CardGroup>
