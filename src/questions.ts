export type AnswerKey = "A" | "B" | "C" | "D";

export type Question = { id: number; question: string; options: Record<AnswerKey, string>; correctAnswer: AnswerKey };

export const questions: Question[] = [
  {
    "id": 1,
    "question": "The synthesis agent receives summarized findings from the web search and document analysis agents, then passes a consolidated summary to\nthe report generator. During testing, you discover the generated reports make factual claims without proper citations – the report generator\ncannot attribute statements to their original sources because that metadata was lost during the summarization steps. What’s the most effective\napproach to ensure proper source attribution in the final reports?",
    "options": {
      "A": "Have the report generator query the web search agent to re-locate sources for claims in the final report.",
      "B": "Have each agent output structured data separating content summaries from source metadata (URLs, document names, page numbers).",
      "C": "Skip summarization and pass full raw outputs from web search and document analysis directly to the report generator.",
      "D": "Instruct the synthesis agent to embed source references inline within its summary text using a consistent citation format."
    },
    "correctAnswer": "B"
  },
  {
    "id": 2,
    "question": "After the web search agent finds 25 sources (120K tokens of raw content), the document analysis agent extracts key insights (15K tokens), and\nthe synthesis agent produces a coherent narrative draft (3K tokens), the coordinator must pass context to the report generation agent for the final\noutput with proper source citations. What context-passing strategy provides the best balance of completeness and efficiency?",
    "options": {
      "A": "Pass the full accumulated context from all prior agents.",
      "B": "Pass the synthesis draft along with a structured source index that maps key claims to their source URLs and relevant excerpts.",
      "C": "Pass only the synthesis draft and have a separate post-processing pipeline match claims to sources and insert citations after the report is\ngenerated.",
      "D": "Pass a condensed summary of all prior stages that preserves the main findings and attributes them to sources by name only."
    },
    "correctAnswer": "B"
  },
  {
    "id": 3,
    "question": "Your multi-agent research pipeline crashed after processing12 of 28 documents. The web search agent had identified relevant sources, the\ndocument analyzer had partially completed extraction, and the synthesizer had begun pattern identification. You need to resume processing\nwithout repeating work or losing fidelity of prior findings. What state management approach best balances information fidelity with context\nefficiency when restoring agent state?",
    "options": {
      "A": "Have each agent persist a structured export to a known location. On resume, the coordinator loads the manifest and injects relevant state\ninto agent prompts.",
      "B": "Index all agent outputs in a shared vector store. When resuming, each agent queries the store using semantic search to retrieve relevant\nprior findings.",
      "C": "Have each agent maintain its own persistent state file and reload it independently at the start of each session.",
      "D": "Persist the coordinator’s conversation log containing all task delegations and responses, providing this to agents when resuming."
    },
    "correctAnswer": "A"
  },
  {
    "id": 4,
    "question": "You’ve configured the system so that all four subagents have access to the complete set of 18 tools. During testing, agents frequently call tools\noutside their specialization – the synthesis agent attempts web searches, and the report generator tries to analyze documents. What is the\nprimary cause of this poor tool selection behavior?",
    "options": {
      "A": "Choosing from 18 tools instead of 4-5 relevant ones increases decision complexity beyond reliable selection thresholds.",
      "B": "The tool definitions consume too much context window space, leaving insufficient room for task content.",
      "C": "The agents’ role descriptions in their system prompts conflict with having access to tools outside that role.",
      "D": "The coordinator cannot track which capabilities each subagent has, leading to misrouted tasks."
    },
    "correctAnswer": "A"
  },
  {
    "id": 5,
    "question": "The coordinator provides detailed step-by-step instructions to the web search subagent, specifying exact search queries, source priorities, and\ndate filters. Production monitoring reveals three issues: (1) the subagent reports “insufficient results” rather than trying alternative approaches\nwhen pre-specified searches fail, (2) research quality drops for emerging topics that don’t match expected patterns, and (3) the subagent rarely\nsurfaces valuable tangential sources. What’s the most effective way to improve subagent adaptability?",
    "options": {
      "A": "Implement a topic classification step where the coordinator categorizes requests as “well-defined” or “exploratory” and uses different\ninstruction styles for each category.",
      "B": "Add explicit fallback directives to the detailed instructions: “If specified searches yield fewer than N results, attempt alternative query\nformulations before reporting failure.”",
      "C": "Remove procedural details entirely, delegating with simple goals like “research X thoroughly” and relying on the subagent’s general\ncapabilities.",
      "D": "Specify research goals and quality criteria (coverage breadth, source diversity, recency) rather than procedural steps, letting the subagent\ndetermine its search strategy."
    },
    "correctAnswer": "D"
  },
  {
    "id": 6,
    "question": "The synthesis agent completes its initial pass but flags that three key research questions remain unanswered because the web search and\ndocument analysis agents didn’t find relevant information on those specific subtopics. The coordinator currently proceeds directly to report\ngeneration, producing reports with incomplete coverage. What change would most effectively improve research completeness?",
    "options": {
      "A": "Have the report generation agent note which research questions couldn’t be answered, so users understand the limitations of the final\noutput.",
      "B": "Increase the initial breadth of queries sent to web search and document analysis to reduce the probability of missing relevant information.",
      "C": "Have the coordinator evaluate synthesis output for gaps, then re-delegate to web search and document analysis with targeted queries\nbefore invoking synthesis again.",
      "D": "Give the synthesis agent direct access to web search tools so it can autonomously fill knowledge gaps without returning control to the\ncoordinator."
    },
    "correctAnswer": "C"
  },
  {
    "id": 7,
    "question": "The web search agent has gathered several relevant sources for a research topic. The document analysis agent now needs to examine these\nsources. How does information typically flow between these two specialized subagents?",
    "options": {
      "A": "The agents communicate through an event-driven message queue, with the document analysis agent subscribing to web search completion\nevents.",
      "B": "The web search agent directly invokes the document analysis agent, passing the discovered sources as parameters.",
      "C": "The coordinator agent receives the web search agent’s output and includes relevant findings in the prompt when invoking the document\nanalysis agent.",
      "D": "Both agents access a shared memory store where the web search agent writes findings and the document analysis agent reads them."
    },
    "correctAnswer": "C"
  },
  {
    "id": 8,
    "question": "Production reviews reveal inconsistent handling of uncertainty in final reports. Sometimes conflicting subagent findings are synthesized into a\nsingle confident statement (losing nuance), while other times reports over-hedge with excessive qualifications (becoming unhelpful). When the\nweb search agent returns “industry analysts estimate $50B market size (methodology varies)” and the document analysis agent returns “peer-\nreviewed study estimates $35B (±$7B, 95% CI),” the coordinator either picks one arbitrarily or produces vague statements like “the market may be\n$35B-$50B depending on factors.” What systematic approach best addresses this?",
    "options": {
      "A": "Configure subagents to only report findings meeting a high-confidence threshold, filtering uncertain information before it reaches the\ncoordinator.",
      "B": "Add a verification subagent that cross-references findings across sources, only passing claims to synthesis that are corroborated by at\nleast two independent sources.",
      "C": "Instruct the synthesis agent to structure reports with explicit sections distinguishing well-established findings from contested ones,\npreserving original source characterizations and methodological context.",
      "D": "Implement a confidence calibration layer that normalizes subagent uncertainty expressions to standardized probability scores (0.0-1.0),\nthen weight-average findings by their calibrated confidence."
    },
    "correctAnswer": "C"
  },
  {
    "id": 9,
    "question": "In production, final reports frequently contain claims without proper source attribution. Investigation shows that while the web search and\ndocument analysis agents correctly attach citations to their outputs, the synthesis agent loses track of which sources support which conclusions\nwhen combining findings. What’s the most effective architectural change?",
    "options": {
      "A": "Require all subagents to output structured claim-source mappings that the synthesis agent must preserve and merge when combining\nfindings from multiple sources.",
      "B": "Maintain complete transcripts of all subagent interactions and add a citation-resolution agent to analyze logs and determine attributions\nbefore report generation.",
      "C": "Add a verification step where the report generator uses semantic similarity matching against original sources to reconstruct which claims\ncame from which documents.",
      "D": "Have the coordinator inject source identifier prefixes into text before each handoff, then parse these prefixes at report generation to\nreconstruct citations."
    },
    "correctAnswer": "D"
  },
  {
    "id": 10,
    "question": "After the web search agent and document analysis agent complete their tasks, the coordinator invokes the synthesis agent. However, the\nsynthesis agent responds that it cannot complete the task because no research findings were provided. What is the most likely cause of this\nissue?",
    "options": {
      "A": "The subagents need to share a single API connection to enable automatic context sharing between invocations.",
      "B": "The synthesis agent needs tools that can fetch results directly from the other agents’ conversation histories.",
      "C": "The coordinator did not include the outputs from the previous agents in the synthesis agent’s prompt.",
      "D": "The synthesis agent’s context window is not large enough to hold the combined outputs from both previous agents."
    },
    "correctAnswer": "C"
  },
  {
    "id": 11,
    "question": "Users report that final reports sometimes lack depth on specific subtopics. Investigation shows that the document analysis agent frequently\nidentifies gaps – for instance, noting “the retrieved sources discuss API authentication but lack details on token refresh patterns” – but under the\ncurrent strict pipeline, this insight isn’t actionable since search has already completed. What’s the most effective architectural change?",
    "options": {
      "A": "Add a research planning agent before the search phase that decomposes topics into specific sub-questions.",
      "B": "Have the analysis agent report specific gaps to the coordinator, which triggers targeted searches and re-invokes analysis until sufficient.",
      "C": "Have the coordinator review analysis output for gap indicators and re-invoke search with gap-informed queries when gaps are detected.",
      "D": "Have the synthesis agent attach confidence scores to each section and flag areas with insufficient coverage for manual review."
    },
    "correctAnswer": "B"
  },
  {
    "id": 12,
    "question": "After the web search and document analysis subagents complete their tasks, the coordinator needs to spawn the synthesis subagent to\nsynthesize the findings. What is the correct approach for providing the synthesis subagent with the information it needs?",
    "options": {
      "A": "Spawn the subagent with only a brief task description, relying on automatic context inheritance from the coordinator",
      "B": "Provide the subagent with tool definitions that allow it to request outputs from other subagents via callbacks",
      "C": "Pass reference identifiers and configure the subagent with read access to a shared memory store where other subagents deposited their\nresults",
      "D": "Include the complete findings from both subagents directly in the synthesis subagent’s prompt"
    },
    "correctAnswer": "D"
  },
  {
    "id": 13,
    "question": "When the agent calls lookup_order and receives order details showing the item was purchased 45 days ago, how does the agentic loop determine\nwhether to call process_refund or escalate_to_human next?",
    "options": {
      "A": "The orchestration layer automatically routes to the next tool based on the order’s status field.",
      "B": "The order details are added to the conversation and the model reasons about which action to take.",
      "C": "The agent executes the remaining steps in a tool sequence planned at the start of the request.",
      "D": "The agent follows a pre-configured decision tree mapping order attributes to specific tool calls."
    },
    "correctAnswer": "B"
  },
  {
    "id": 14,
    "question": "After investigating a billing dispute over 25+ turns, you’ve identified that duplicate charges occurred due to a payment gateway timeout triggering\nretry logic. The required refund ($847) exceeds your $500 authorization limit You need to call escalate_to_human, and the human agent won’t have\naccess to your conversation transcript. What context should you pass to enable effective resolution?",
    "options": {
      "A": "A structured summary: customer ID, root cause, refund amount, and recommended action.",
      "B": "Your diagnosis and the refund amount only.",
      "C": "The customer’s original complaint verbatim plus the tool result excerpts showing duplicate transactions.",
      "D": "The complete conversation transcript with all tool results."
    },
    "correctAnswer": "A"
  },
  {
    "id": 15,
    "question": "Your agent is handling a billing dispute. After calling get_customer and lookup_order, it identifies that the dispute involves a promotional pricing\nerror requiring manager approval – beyond the agent’s authorization level. How should the workflow handle this mid-process escalation?",
    "options": {
      "A": "Compile a structured handoff with customer details, order info, and the identified issue before calling escalate_to_human.",
      "B": "Persist the complete conversation and tool response history to a database, then call escalate_to_human with a reference ID.",
      "C": "Call escalate_to_human passing only the customer’s original message.",
      "D": "Attempt the refund with process_refund anyway, escalating only if the system rejects the transaction."
    },
    "correctAnswer": "A"
  },
  {
    "id": 16,
    "question": "You’re implementing the escalation logic for when the agent should call escalate_to_human. Your team proposes four different approaches for\ntriggering escalation. Which approach will most reliably identify cases that genuinely require human intervention?",
    "options": {
      "A": "Implement sentiment analysis that monitors for frustration indicators (negative language, repeated questions, exclamation marks) and\ntrigger escalation when the frustration score exceeds a configured threshold.",
      "B": "Configure the agent to escalate after three consecutive tool calls that fail to resolve the customer’s stated issue, ensuring a reasonable\nattempt before involving a human.",
      "C": "Instruct the agent to escalate when the customer requests a human, when the issue requires policy exceptions, or when the agent cannot\nmake meaningful progress.",
      "D": "Build a rules engine that maps specific issue types, customer segments, and product categories to escalation decisions, removing the need\nfor model judgment calls."
    },
    "correctAnswer": "C"
  },
  {
    "id": 17,
    "question": "Your order management system requires tools for three distinct operations: issuing refunds (requires amount and reason), canceling orders\n(requires reason), and requesting reshipments (requires shipping address). Each operation shares an order_id parameter but has different\nadditional requirements. You notice during testing that with your current unified tool design, the agent frequently omits required parameters or\nincludes irrelevant ones. What design change will most effectively improve parameter accuracy?",
    "options": {
      "A": "Keep one unified tool with a nested operation_details object parameter whose internal structure varies by operation type, documented in the\ntool description.",
      "B": "Keep one unified tool but add JSON Schema if-then-else conditionals to enforce that parameters like amount are required only when the\noperation type is “refund”.",
      "C": "Split into three separate tools (issue_refund, cancel_order, request_reshipment), each defining only the parameters required for that specific\noperation.",
      "D": "Keep one unified tool with all parameters marked optional, but add detailed few-shot examples in the system prompt showing correct\nparameter combinations for each operation type."
    },
    "correctAnswer": "C"
  },
  {
    "id": 18,
    "question": "Your post_content tool requires user confirmation before publishing. The current workflow displays “Ready to post to social media. Confirm?” and\nanalytics show users approve 98% of requests within 2 seconds. Post-mortems reveal incidents where posts went to wrong accounts, were\nscheduled for wrong times, or contained errors – all confirmed by users without catching the mistakes. How should you redesign the confirmation\nworkflow?",
    "options": {
      "A": "Auto-approve routine posts and only require explicit confirmation for unusual patterns like posting to new accounts or large audiences",
      "B": "Require users to type a confirmation phrase instead of clicking a button",
      "C": "Add a mandatory waiting period before the confirm option becomes available",
      "D": "Include the complete post text, target account, scheduled time, and platform in the confirmation request"
    },
    "correctAnswer": "D"
  },
  {
    "id": 19,
    "question": "Your agent uses three tools: get_property_details(property_id) returns data including street address, get_price_history(property_id) returns\nhistorical pricing, and get_neighborhood_info(address) returns area statistics. You observe that get_neighborhood_info always requires\nget_property_details first just to extract the address, even when users specify the property by ID. This creates unnecessary latency and failure\ncoupling – if the first call fails, the neighborhood request also fails. What tool design change best addresses this?",
    "options": {
      "A": "Create a lookup_address(property_id) helper tool for retrieving addresses.",
      "B": "Add retry logic and timeout handling to get_property_details.",
      "C": "Change get_neighborhood_info to accept property_id, resolving the address internally.",
      "D": "Consolidate into a single get_property_with_neighborhood(property_id) tool returning both datasets."
    },
    "correctAnswer": "C"
  },
  {
    "id": 20,
    "question": "Your update_user_profile tool accepts a user_id (required) and an optional fields_to_update object. In testing, Claude frequently omits user_id or\npasses incorrectly structured data. What is most critical for helping Claude understand what parameter values to provide?",
    "options": {
      "A": "Strict JSON Schema type constraints marking user_id as required and defining fields_to_update as an object type",
      "B": "Verbose parameter names encoding format hints, such as user_id_string_uuid_format",
      "C": "Detailed error responses explaining why invalid parameter values were rejected",
      "D": "Clear parameter descriptions explaining expected format, such as “user_id: UUID of the user to update (required)”"
    },
    "correctAnswer": "D"
  },
  {
    "id": 21,
    "question": "Your document extraction tool uses ML models to extract invoice fields (vendor, amount, date). The models return confidence scores (0.0-1.0) for\neach extracted field. In production, you observe: (1) the agent proceeds with low-confidence extractions that are incorrect 23% of the time, and (2)\nthe agent requests unnecessary human review for 31% of extractions that were actually correct. How should you restructure the tool’s output?",
    "options": {
      "A": "Return fields with their raw confidence scores and add detailed few-shot examples to your system prompt demonstrating how to interpret\ndifferent confidence ranges and when to request human review.",
      "B": "Return fields with confidence scores, plus a request_review boolean computed using your tested confidence thresholds, along with a\nreview_reasons array explaining which fields triggered review.",
      "C": "Compute an aggregate extraction_quality score across all fields and return it alongside the extracted values. Include a text summary\ndescribing the overall extraction reliability.",
      "D": "Return fields organized into verified and needs_verification objects based on confidence thresholds."
    },
    "correctAnswer": "B"
  },
  {
    "id": 22,
    "question": "Your product search tool queries an external catalog API and returns matching items. In production, you observe the agent frequently retries\nsearches immediately after receiving zero results, treating “no matches found” as a failure requiring retry. The external API returns HTTP 200 with\nan empty results array – a valid response. How should you restructure the tool’s result to help the agent correctly interpret empty result sets?",
    "options": {
      "A": "Add a suggestions field containing alternative search strategies when results are empty, helping guide the agent toward more productive\nfollow-up queries.",
      "B": "Return a natural language string describing the outcome, allowing the agent to interpret the result contextually based on the message\ncontent.",
      "C": "Return a result object with isError: true and a message explaining no products matched.",
      "D": "Return a structured result with a success boolean and results array, reserving isError: true for actual execution failures only."
    },
    "correctAnswer": "D"
  },
  {
    "id": 23,
    "question": "Your MCP server includes archive_file(file_id) and delete_file(file_id) tools. Production logs show the agent calls delete_file when users ask to\n“remove old backups,” but company policy requires archiving backup files. Both tools currently have minimal descriptions: “Archives a file” and\n“Deletes a file.” Which change most directly improves tool selection for this scenario?",
    "options": {
      "A": "Expand tool descriptions to clarify use cases, adding guidance like “Do not use for backup files” to delete_file.",
      "B": "Add a confirmation step that requires users to type “CONFIRM DELETE” before delete_file executes.",
      "C": "Implement server-side validation that rejects delete_file calls for files tagged as backups, returning an error message suggesting\narchive_file.",
      "D": "Add few-shot examples to the system prompt demonstrating that requests involving “backup” or “old” should use archive_file."
    },
    "correctAnswer": "A"
  },
  {
    "id": 24,
    "question": "Your track_shipment(tracking_id) tool queries an external logistics API that sometimes fails – the API may be temporarily unavailable, the tracking\nID may be malformed, or the shipment may not exist. Currently, your tool raises a Python exception when errors occur. Users report the agent\ngives unhelpful responses like “I’m having trouble with that request” instead of suggesting alternatives such as verifying the tracking number\nformat or checking by order number. How should you handle errors in tool results?",
    "options": {
      "A": "Return a generic error response (e.g., {\"success\": false, \"error\": \"lookup_failed\"}) for all failure cases to maintain a consistent schema and\navoid exposing internal error details.",
      "B": "Return structured error information as normal tool output including error type, recoverability status, and actionable context for the user.",
      "C": "Create dedicated error-recovery tools (retry_tracking_lookup, search_by_order_number) that the model can invoke after the primary tracking\ntool returns a failure indicator.",
      "D": "Implement retry logic with exponential backoff inside the tool implementation so transient errors are automatically handled and only return\na result after all retry attempts are exhausted."
    },
    "correctAnswer": "B"
  },
  {
    "id": 25,
    "question": "Your MCP server implements a check_availability tool that queries an external calendar API. During testing, you encounter three error conditions:\n(1) the tool is called with a malformed request missing the required user_email parameter, (2) the calendar API returns a 404 because the\nspecified user doesn’t exist in the calendar system, and (3) the calendar API returns a 503 because the service is temporarily unavailable. How\nshould each error be reported according to MCP’s error handling design?",
    "options": {
      "A": "Report all three as tool results with isError: true.",
      "B": "Report errors 1 and 2 as JSON-RPC protocol errors; report error 3 as a tool result with isError: true.",
      "C": "Report error 1 as a JSON-RPC protocol error; report errors 2 and 3 as tool results with isError: true.",
      "D": "Report all three as JSON-RPC protocol errors."
    },
    "correctAnswer": "C"
  },
  {
    "id": 26,
    "question": "Your send_notification tool calls third-party messaging APIs. When these services time out during delivery, you cannot determine whether the\nmessage was actually sent. Currently, the tool returns is_error: true with a generic “Notification failed” message for all timeouts. Production\nmonitoring reveals agents automatically retry these failures, frequently causing users to receive duplicate notifications. How should you modify\nthe error response?",
    "options": {
      "A": "Return is_error: true with a structured field retry_safe: true for timeouts, distinguishing them from permanent failures that should not be\nretried.",
      "B": "Return is_error: true with a message communicating uncertainty: “Timeout – status unknown. Message may have been sent. Avoid retry.”",
      "C": "Return is_error: true with a message encouraging retry: “Delivery service temporarily unavailable. Please retry the notification.”",
      "D": "Return is_error: true with the original message content echoed back."
    },
    "correctAnswer": "B"
  },
  {
    "id": 27,
    "question": "Your control_device tool manages smart home devices through external APIs. When a device doesn’t respond within the timeout period, the tool\nreturns an error. Production logs show that the agent simply tells users “the device is not responding” without offering helpful next steps. Which\nerror response structure would best enable the agent to provide useful follow-up?",
    "options": {
      "A": "Set is_error: true with a structured technical error containing the device ID, timeout duration, and raw API response code for debugging\npurposes.",
      "B": "Set is_error: true with a brief “Device offline” message and provide a separate tool the agent can call to retrieve context-specific\ntroubleshooting suggestions.",
      "C": "Set is_error: false with an optimistic message indicating the command was dispatched successfully but device acknowledgment is still\npending.",
      "D": "Set is_error: true with a message explaining the likely cause and suggesting troubleshooting steps the agent can offer the user."
    },
    "correctAnswer": "D"
  },
  {
    "id": 28,
    "question": "Your expense reimbursement agent processes employee requests using a process_reimbursement tool. Company policy requires that\nreimbursements above $500 must be approved by a manager before funds are disbursed. The agent handles hundreds of requests daily, and you\nneed the threshold enforcement to be tamper-proof regardless of how the agent is prompted. Which design ensures the $500 approval threshold\ncannot be bypassed?",
    "options": {
      "A": "The process_reimbursement tool accepts amount and details, and internally enforces the threshold: amounts <$500 are auto-disbursed and\nthe tool returns a success confirmation; amounts >$500 cause the tool to create a pending approval request and return a status indicating\nmanager review is pending.",
      "B": "The process_reimbursement tool accepts an approved_by_manager: boolean parameter. The system prompt instructs the agent to only set\nthis to true after confirming that a manager has approved the request. A nightly audit script reviews all reimbursements where\napproved_by_manager was set to true.",
      "C": "Provide two tools: auto_reimburse (hard-coded limit of $500) and request_manager_approval. Include detailed system prompt instructions\ntelling the agent to check the amount and call the appropriate tool. Add a PostToolUse hook that logs which tool was called for auditing.",
      "D": "Implement the threshold check in a PreToolUse hook that inspects the amount parameter before process_reimbursement executes. If the\namount exceeds $500, the hook modifies the tool call to add a requires_approval: true flag, which the tool checks before disbursing."
    },
    "correctAnswer": "A"
  },
  {
    "id": 29,
    "question": "Your content curation agent discovers articles, analyzes each for relevance, then adds selected articles to themed collections. With separate\ndiscover_articles(topic), analyze_article(id), and add_to_collection(article_id, collection_id) tools, you observe 18+ sequential tool calls per\nrequest, causing latency issues. The agent must make editorial judgments about which articles fit a collection’s theme – this requires seeing all\ncandidates with their analysis scores simultaneously to select a cohesive set. What tool composition best addresses efficiency while preserving\neditorial judgment?",
    "options": {
      "A": "Keep all tools separate but implement response caching for analyze_article calls.",
      "B": "Create a curate_collection(topic, collection_id) tool that handles discovery, analysis, and selection internally using configurable quality\nthresholds.",
      "C": "Create a discover_and_analyze(topic) composite tool that returns all candidates with their analysis scores, keeping add_to_collection\nseparate for selective calls.",
      "D": "Add a preview_curation(topic, collection_id) tool that shows what would be added based on predefined rules, with an approve_curation()\ntool to confirm."
    },
    "correctAnswer": "C"
  },
  {
    "id": 30,
    "question": "The document analysis agent has a single analyze_documnet tool that takes a document and a free-text instruction parameter. During evaluation,\nrequests like “extract the key financial metrics” often return narrative summaries, while “summarize the methodology” sometimes returns raw data\ntables. The synthesis agent reports that 35% of analysis results require re-requests with clarified instructions. What’s the most effective way to\nimprove reliability?",
    "options": {
      "A": "Have the coordinator pre-classify each analysis request before passing instructions to the document analysis agent",
      "B": "Keep the single tool but add an analyze_type enum parameter requiring explicit selection between extraction, summarization, and\nverification modes",
      "C": "Enhance the tool description with detailed examples showing how different instruction phrasings should map to different output formats",
      "D": "Split the generic tool into purpose-specific tools – extract_data_points, summarize_content, verify_claim_against_source – each with\ndefined input/output contracts"
    },
    "correctAnswer": "D"
  },
  {
    "id": 31,
    "question": "Compliance requires that refunds exceeding $500 must automatically escalate to a human agent – this rule cannot be left to model discretion.\nDespite clear system prompt instructions, production logs show the agent occasionally processes high-value refunds directly (3% failure rate).\nHow should you achieve guaranteed compliance?",
    "options": {
      "A": "Modify the refund tool to return an error with message “Amount exceeds policy limit – please escalate” when threshold is exceeded.",
      "B": "Add few-shot examples to the prompt showing correct escalation behavior at various refund amounts ($400, $500, $600).",
      "C": "Implement a hook to intercept tool calls; when the refund process amount exceeds $500, block it and invoke human escalation.",
      "D": "Strengthen the system prompt with emphatic language: “CRITICAL POLICY: Refunds over $500 MUST trigger human escalation. NEVER\nprocess these directly.”"
    },
    "correctAnswer": "C"
  },
  {
    "id": 32,
    "question": "Production logs reveal inconsistent error handling: when lookup_order fails, the agent sometimes retries 5+ times (wasteful when the order ID\ndoesn’t exist), sometimes escalates immediately (premature for temporary network issues), and sometimes asks users for clarification\n(inappropriate when the issue is a backend permission error). Investigation shows your MCP tool returns uniform error responses: {\"isError\": true,\n\"content\": [{\"type\": \"text\", \"text\": \"Operation failed\"}]}. The agent cannot distinguish between error types. What’s the most effective improvement?",
    "options": {
      "A": "Create an analyze_error MCP tool the agent calls after any failure to determine the error category and recommended action.",
      "B": "Add few-shot examples to the system prompt demonstrating how to interpret error message patterns and select appropriate responses for\neach.",
      "C": "Enhance error responses with structured metadata: include errorCategory (transient/validation/permission), isRetryable boolean, and a\ndescription of what caused the failure.",
      "D": "Implement retry logic with exponential backoff in your MCP server for all errors, returning to the agent only after retries are exhausted."
    },
    "correctAnswer": "C"
  },
  {
    "id": 33,
    "question": "When implementing your lookup_order MCP tool, the backend sometimes returns errors (e.g., “Order not found” or temporary database failures).\nWhat is the correct pattern for communicating these errors back to the agent?",
    "options": {
      "A": "Throw an exception from the tool handler so the agent framework can catch and log it",
      "B": "Return the error message in the tool result content with the isError flag set to true",
      "C": "Log the error server-side and return an empty result to avoid confusing the model",
      "D": "Return a success response with a “status” field indicating the error type"
    },
    "correctAnswer": "B"
  },
  {
    "id": 34,
    "question": "Your process_refund tool returns two types of errors: technical errors (“503 Service Unavailable”, “Connection timeout”) that are transient (5% of\ncalls), and business errors (“Order exceeds 30 day return window”, “Item already refunded”) that are permanent (12% of calls). Monitoring shows\nthe agent wastes 3-4 turns retrying business errors that can never succeed. Currently, both error types return only a plain text message to Claude.\nWhat’s the most effective way to reduce wasted retries while improving customer-facing response quality?",
    "options": {
      "A": "Implement automatic retry logic at the tool level for technical errors only, passing business errors to Claude without retries.",
      "B": "Add few-shot examples showing how to distinguish retriable from non-retriable errors by parsing error message text.",
      "C": "Return structured error responses with retriable: false for business errors and a customer-friendly explanation for Claude to use.",
      "D": "Add a check_refund_eligibility tool that must be called before process_refund to prevent business rule violations."
    },
    "correctAnswer": "C"
  },
  {
    "id": 35,
    "question": "Your get_portfolio_value tool returns the total value of a user’s investment portfolio. You’re deciding between returning a structured JSON object\nwith explicit fields versus returning the information as a formatted text string. What is the primary advantage of using structured output with\ndefined fields?",
    "options": {
      "A": "JSON schemas automatically validate that the underlying API returned correct data before the agent processes it.",
      "B": "Structured JSON consumes significantly fewer tokens than natural language, substantially reducing API costs.",
      "C": "Structured JSON is processed deterministically by the model, significantly improving accuracy when extracting values.",
      "D": "The agent can reliably extract specific values without parsing free-form text, reducing errors in subsequent operations."
    },
    "correctAnswer": "D"
  },
  {
    "id": 36,
    "question": "The coordinator agent has AgentDefinitions configured for all four specialized subagents, each with appropriate descriptions, prompts, and tool\nrestrictions. During testing, you notice the coordinator correctly reasons about when to delegate – it generates messages like “I’ll ask the web\nsearch agent to find sources on this topic” – but no subagent execution ever occurs. The coordinator then proceeds as if the delegation happened\nand continues with incomplete information. Logs show no errors. What is the most likely cause?",
    "options": {
      "A": "The coordinator’s max_tokens setting is too low, causing the Task tool invocation to be truncated before the subagent type parameter can\nbe specified.",
      "B": "The coordinator’s allowedTools configuration doesn’t include “Task”, so while it can reason about delegation, it cannot invoke the tool\nrequired to spawn subagents.",
      "C": "The AgentDefinitions are configured correctly, but the coordinator’s system prompt doesn’t explicitly list the available subagent types,\npreventing the model from knowing they can be invoked.",
      "D": "Subagent context isolation means task descriptions from the coordinator don’t automatically reach subagents; you need to configure\nexplicit context forwarding in ClaudeAgentOptions."
    },
    "correctAnswer": "B"
  },
  {
    "id": 37,
    "question": "Your conversational assistant frequently generates multiple clarifying questions when users make ambiguous requests. When a user asks “Can\nyou help me with the report?”, the assistant responds: “I’d be happy to help! Could you tell me: 1) Which report? 2) What kind of help – drafting,\nreviewing, or formatting? 3) What’s your deadline?”\nUser analytics show a 40% conversation abandonment rate after these multi-question responses. What’s the most effective way to reduce friction\nwhile appropriately handling ambiguity?",
    "options": {
      "A": "Limit the assistant to one clarifying question per turn, using conversation history to accumulate answers over multiple exchanges rather\nthan requesting everything upfront.",
      "B": "Add a preprocessing step using a smaller model to classify request ambiguity on a 1-5 scale, routing high-ambiguity requests to a\nclarification dialog and low-ambiguity requests directly to the assistant.",
      "C": "Modify the system prompt to instruct the assistant to make reasonable assumptions from available context, state those assumptions\nexplicitly, and offer to adjust if the interpretation is wrong.",
      "D": "Create a lookup table of common request patterns with predefined default interpretations, having the assistant respond with those defaults\nwithout stating the assumptions made."
    },
    "correctAnswer": "C"
  },
  {
    "id": 38,
    "question": "After 30+ turns, your conversational assistant shows noticeably slower responses and occasionally produces less coherent outputs. Investigation\nreveals: (1) average conversations reach 50,000 tokens by turn 35, (2) production logs show 94% of user messages only reference the previous 3-\n5 exchanges, (3) the 6% of queries referencing earlier context typically ask about information the user could easily re-state. Your goal is to\nimprove response speed and quality while maintaining good user experience. What’s the most effective approach?",
    "options": {
      "A": "Enable prompt caching and continue sending the complete conversation history, using cached prefixes to reduce per-request costs while\npreserving all context.",
      "B": "Build a retrieval system that stores all conversation turns and uses semantic search to pull in relevant historical context only when the\ncurrent query appears to reference past information.",
      "C": "Implement a summarization layer that progressively compresses older conversation turns into a running summary while keeping the most\nrecent 5-6 turns verbatim, maintaining full historical context in condensed form.",
      "D": "Implement a sliding window keeping only the system prompt and last 8-10 turns. When users reference earlier context, acknowledge the\nlimitation and ask them to re-state the relevant information."
    },
    "correctAnswer": "C"
  },
  {
    "id": 39,
    "question": "Production monitoring shows that follow-up queries like “summarize what we learned about market trends” consistently take 40+ seconds.\nInvestigation reveals the coordinator spawns the synthesis subagent for each summarization request, passing 80K+ tokens of accumulated\nfindings. The coordinator already has these findings in its context from orchestrating the research. What’s the most effective way to improve\nresponse time for these follow-up summaries?",
    "options": {
      "A": "Enable prompt caching on the synthesis subagent to reduce the overhead of repeatedly transferring the same research findings.",
      "B": "Have the coordinator handle straightforward summarization requests directly using its existing context, reserving subagent spawning for\ncomplex analysis.",
      "C": "Pre-generate and cache summaries at multiple granularities whenever new findings accumulate.",
      "D": "Spawn the synthesis subagent with reduced context and have it request specific findings from the coordinator on-demand."
    },
    "correctAnswer": "B"
  },
  {
    "id": 40,
    "question": "A customer raises three separate issues during one session: a refund inquiry (turns 1-15), a subscription question (turns 16-30), and a payment\nmethod update (turns 31-45). At turn 48, the customer asks “What happened with my refund?” The conversation is approaching context limits.\nWhat strategy best maintains the agent’s ability to address all issues throughout the session?",
    "options": {
      "A": "Extract and persist structured issue data (order IDs, amounts, statuses) into a separate context layer.",
      "B": "Summarize earlier turns into a narrative description, preserving full message history only for the active issue.",
      "C": "Rely on MCP tools to re-fetch relevant information on demand when the customer references earlier issues.",
      "D": "Implement sliding window context that retains the most recent 30 turns."
    },
    "correctAnswer": "A"
  },
  {
    "id": 41,
    "question": "During a billing dispute resolution, your agent successfully retrieves customer info via get_customer and order details via lookup_order, but when\nattempting to call process_refund, the tool returns a timeout error. The agent has enough information to explain the charges and verify refund\neligibility, but cannot actually process the refund due to the backend failure. What approach best balances first-contact resolution with appropriate\nerror handling?",
    "options": {
      "A": "Explain the billing confirm refund eligibility, acknowledge the system issue preventing immediate processing, and offer escalation or retry\nlater",
      "B": "Confirm the refund will be processed and close the conversation, since the system has all necessary information to complete it\nautomatically",
      "C": "Implement automatic retries with exponential backoff for process_refund, keeping the conversation open until the refund is successfully\nprocessed",
      "D": "Escalate immediately to a human agent since the refund action cannot be completed"
    },
    "correctAnswer": "A"
  },
  {
    "id": 42,
    "question": "Your agent has called lookup_order multiple times while investigating a customer’s return requests. Each response includes 40+ fields (items,\nshipping details, payment info, status history). Tool outputs now represent the majority of the conversation’s context. The customer mentions two\nmore orders they want to discuss. What’s the most effective approach before making additional lookups?",
    "options": {
      "A": "Move all tool responses to a vector database with semantic indexing, retrieving relevant portions as the conversation continues",
      "B": "Proceed with additional lookups without modifying the existing tool output context",
      "C": "Have the model generate a natural language summary of each order’s key details, replacing structured responses with prose descriptions",
      "D": "Extract only the return-relevant fields (items, purchase date, return window, status) from each existing order response, removing verbose\ndetails"
    },
    "correctAnswer": "D"
  },
  {
    "id": 43,
    "question": "A customer writes: “I’ve been going back and forth on this return for days. I just want to speak to someone who can actually help me.” The agent\nhas confirmed via lookup_order that the return is straightforward – within policy and eligible for immediate processing. What should the agent do?\n",
    "options": {
      "A": "Process the refund via process_refund to resolve the underlying issue, then inform them it’s complete",
      "B": "Acknowledge frustration, inform them this is resolvable now, and offer to complete it or escalate",
      "C": "Call escalate_to_human immediately to honor the customer’s request",
      "D": "Ask what specifically hasn’t worked in previous attempts before deciding whether to escalate or resolve automatically"
    },
    "correctAnswer": "B"
  },
  {
    "id": 44,
    "question": "A customer sends: “This is frustrating. I’ve explained my issue twice and nothing is being resolved. I want to talk to a real person NOW.” The agent\nhas not yet called any tools to investigate their account. What should the agent do?\n",
    "options": {
      "A": "Immediately call escalate_to_human with the conversation history.",
      "B": "Briefly explain what the agent can help with and offer to resolve the issue quickly, escalating only if the customer repeats their request.",
      "C": "First call get_customer and lookup_order to gather account context, then escalate to a human agent.",
      "D": "Acknowledge the frustration and ask one targeted question to understand the specific issue before escalating."
    },
    "correctAnswer": "A"
  },
  {
    "id": 45,
    "question": "A customer returns 4 hours after the initial session about the same billing dispute. The previous 32-turn session contains lookup_order results\nshowing “Status: PENDING, Expected resolution: 24-48 hours.” In testing, you observe that when resuming sessions with stale tool results, the\nagent often references the outdated data in responses (e.g., “I see your refund is still being processed”) even after subsequent fresh tool calls\nreturn different information. What approach most reliably handles returning customers?\n",
    "options": {
      "A": "Start a new session, inject a structured summary of the previous interaction (issue type, actions taken, resolution status), then make fresh\ntool calls before engaging.",
      "B": "Resume with full history but filter out previous tool_result messages before resuming, keeping only the human/assistant turns so the agent\nmust re-fetch needed data.",
      "C": "Resume with full history and configure the agent to automatically re-call all previously-used tools at session start to ensure data freshness.",
      "D": "Resume with full history and add a system prompt instruction telling the agent to always prefer the most recent tool results when multiple\ncalls to the same tool exist in context."
    },
    "correctAnswer": "A"
  },
  {
    "id": 46,
    "question": "The agent verifies customer identity through a multi-step process before resetting passwords. During testing, you notice that after the customer\nanswers the third verification question, the agent asks them to provide their name again, as if the earlier exchange never happened. What’s the\nmost likely cause of this behavior?",
    "options": {
      "A": "The verification tool is clearing the agent’s internal state after each successful validation step.",
      "B": "Claude’s memory retention is limited to two conversational turns by default, requiring explicit configuration to extend it.",
      "C": "The conversation history isn’t being passed in subsequent API requests.",
      "D": "The prompt lacks instructions telling Claude to remember information across multiple exchanges."
    },
    "correctAnswer": "C"
  },
  {
    "id": 47,
    "question": "You are building a customer support resolution agent using the Claude Agent SDK. The agent handles high-ambiguity requests like returns, billing\ndisputes, and account issues. It has access to your backend systems through custom Model Context Protocol (MCP) tools ( get_customer,\nlookup_order , process_refund , escalate_to_human ). Your target is 80%+ first-contact resolution while knowing when to escalate.\nAfter expanding the agent’s MCP tools with delivery-specific capabilities ( check_delivery_status , contact_driver , issue_credit , apply_promo_code\n, update_delivery_address , reschedule delivery ), the total tool count has grown from 4 to 10. Your evaluation suite shows tool selection accuracy\nhas dropped from 88% to 71%. Log analysis reveals the majority of errors involve the agent selecting between semantically overlapping tools —\ncalling issue_credit when process_refund was correct, and calling check_delivery_status when lookup_order already returns the needed data.\nWhich approach structurally eliminates the semantic overlap identified in the logs as the error source?",
    "options": {
      "A": "Enable the tool search tool with defer_loading on the six new tools, keeping the original four always loaded, so the agent dynamically\ndiscovers specialized tools only when needed.",
      "B": "Split the tools across two sub-agents – a “financial resolution” agent with process_refund , issue_credit ,and apply_promo_code , and a\n“delivery operations” agent with the remaining delivery tools – with a coordinator routing between them.",
      "C": "Add few-shot examples to the system prompt demonstrating correct selection for each ambiguous tool pair, such as showing when\nissue_credit applies versus when process_refund is appropriate.",
      "D": "Consolidate semantically overlapping tools – merge issue_credit and process_refund into a single resolve_compensation tool with an\naction parameter, and fold check_delivery_status into lookup_order with an optional include_tracking flag."
    },
    "correctAnswer": "D"
  },
  {
    "id": 48,
    "question": "During testing, you find that when a customer says “I need a refund for my recent purchase,” the agent calls process _refund immediately – but\npopulates the required order_id parameter with a plausible-looking but fabricated value instead of first calling lookup_order to retrieve the actual\norder ID. The refund call fails because the fabricated ID doesn’t exist. Which change directly addresses the root cause of the agent fabricating the\norder_id value?",
    "options": {
      "A": "Switch tool_choice from “auto” to “any” to force the agent to make a tool call on every turn.",
      "B": "Update the process_refund tool description to explicitly state that order_id must be obtained from a prior lookup_order call and must never\nbe assumed or invented.",
      "C": "Pre-parse incoming customer messages to extract any order IDs mentioned, and inject them into the conversation context before passing\nto Claude.",
      "D": "Add server-side validation that checks whether the order_id exists in your database before executing the refund, returning an error to the\nagent if not found."
    },
    "correctAnswer": "B"
  },
  {
    "id": 49,
    "question": "Anthropic’s tool use documentation states: “Write instructive error messages. Instead of generic errors like ‘failed’, include what went wrong and\nwhat Claude should try next.” A billing dispute agent uses lookup_order, which catches all exceptions and returns a tool_result with is_error: true\nand the message “Tool execution failed”. Monitoring shows two failure modes: the agent retries the identical call until hitting the turn limit, or it\nimmediately calls escalate_to_human without trying alternative tools. Which change follows the documented recommendation and gives Claude\nthe information it needs to select the correct recovery action for each error type?",
    "options": {
      "A": "Implement retry logic with exponential backoff inside each tool implementation so transient errors are resolved transparently within the\ntool before any failure result is surfaced to Claude in the agentic loop.",
      "B": "Add an error classification step in the agentic loop that intercepts tool errors before Claude sees them, tags each as “retry,”\n“try_alternative,” or “escalate,” and appends that recommendation to the tool result.",
      "C": "Remove is_error: true and return the error details as normal tool content, so Claude reasons about the response as data rather than treating\nit as a flagged failure condition that biases retry behavior.",
      "D": "Return error-type-specific messages with is_error: true, e.g., “Order not found-try get_customer to search by phone” for data errors and\n“Database timeout (transient)-retry should succeed” for infrastructure errors."
    },
    "correctAnswer": "D"
  },
  {
    "id": 50,
    "question": "Production logs show that when the agent handles complex billing disputes requiring 6+ tool calls, it sometimes exhausts its max_turns limit after\ngathering data but before completing resolution or escalating. The team’s goal is to guarantee that every customer interaction ends with either a\ncompleted resolution or a human handoff, regardless of how the agent loop terminates. Which approach achieves this guarantee?",
    "options": {
      "A": "Add system prompt instructions telling the agent to call escalate_to_human with a summary of its findings whenever it determines it\ncannot complete resolution within its remaining actions.",
      "B": "Split the workflow into two sequential agent invocations – a first agent gathers information via get_customer and lookup_order, then a\nsecond agent receives that data and handles process_refund or escalate_to_human, each with separate turn budgets.",
      "C": "Add orchestration-layer code that checks the agent’s outcome after each loop termination – if the loop ended without a completed\nresolution or escalation, programmatically call escalate_to_human with the accumulated conversation context and tool results.",
      "D": "Implement a pre-tool-use hook that counts tool invocations and terminates the loop with an automatic escalation once the agent reaches\n80% of its max_turns limit."
    },
    "correctAnswer": "C"
  },
  {
    "id": 51,
    "question": "A customer contacts the agent about a warranty claim on a power drill. Resolving this requires multiple sequential tool calls: get_customer to look\nup their account, lookup_order to find the purchase details, and then either process_refund or escalate_to_human depending on warranty\neligibility. You’re implementing the agentic loop that orchestrates these steps using the Claude API. What is the primary mechanism your\napplication uses to determine whether to continue the loop or stop?\n",
    "options": {
      "A": "You manually set the tool_choice parameter to “none” after the final expected tool call to force Claude to stop requesting tools.",
      "B": "You check whether Claude's response contains a text content block – if text is present, the agent has produced its final answer and the loop\nshould exit.",
      "C": "You track the number of tool calls made and exit the loop once a preconfigured maximum is reached.",
      "D": "You check the stop_reason field in each API response – the loop continues while it equals “tool_use” and exits when it changes to\n“end_turn” or another terminal value."
    },
    "correctAnswer": "D"
  },
  {
    "id": 52,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYour team’s CLAUDE.md includes a rule: “Use 4-space indentation and always run Prettier formatting.” Despite this, code reviews reveal that\nroughly 30% of files Claude Code generates use inconsistent formatting – sometimes 2-space indentation, sometimes missing trailing commas.\nAdding emphasis (“IMPORTANT: You MUST use Prettier formatting”) reduces violations to about 15%, but doesn’t eliminate them. What is the\nmost effective way to ensure all generated code is consistently formatted?",
    "options": {
      "A": "Configure a PostToolUse hook with an Edit|Write matcher that automatically runs Prettier on each file Claude modifies.",
      "B": "Split the formatting rules into path-scoped .claude/rules/files that load when Claude works on matching file types.",
      "C": "Extract the formatting rules into a dedicated skill that Claude loads automatically when generating code, with more detailed examples of\ncorrect formatting.",
      "D": "Add a Stop hook with a prompt-based check that evaluates whether generated code follows formatting standards and prompts Claude to fix\nviolations."
    },
    "correctAnswer": "A"
  },
  {
    "id": 53,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs. direct execution.\nYou need to add a date validation check ensuring event dates are in the future. This requires adding a conditional statement to one existing\nfunction in a single file. What is the most appropriate approach?",
    "options": {
      "A": "Enter plan mode first to create a detailed implementation strategy before making the change.",
      "B": "Enter plan mode to analyze how the validation might impact other parts of the reservation flow.",
      "C": "Use direct execution to make the change.",
      "D": "Start with extended thinking mode enabled to ensure thorough reasoning about the validation logic."
    },
    "correctAnswer": "C"
  },
  {
    "id": 54,
    "question": "Your infrastructure-as-code repository includes Terraform modules (/terraform/), Kubernetes manifests (/kubernetes/), and CI/CD pipeline scripts\n(/pipelines/). Each requires different conventions, but your single root CLAUDE.md has grown to 500+ lines. When developers work on Kubernetes\nfiles, Terraform-specific rules load into context unnecessarily, consuming tokens.\nWhat is the best approach to reorganize so only relevant guidance loads when editing specific file types?",
    "options": {
      "A": "Split content into subdirectory CLAUDE.md files (/terraform/CLAUDE.md, /kubernetes/CLAUDE.md), so Claude loads directory-specific\nguidance.",
      "B": "Keep the root CLAUDE.md and use @path/to/import syntax to modularly include tool-specific guidance files from separate documents.",
      "C": "Restructure the root CLAUDE.md into clearly labeled sections with headers (e.g, “## Terraform Conventions”), improving organization and\nreadability.",
      "D": "Create files in .claude/rules/ with YAML frontmatter path-scoping (e.g., paths: [“terraform/**/*”]), loading rules only when editing matching\nfiles."
    },
    "correctAnswer": "D"
  },
  {
    "id": 55,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYou’re implementing a complex graph traversal algorithm with specific performance requirements and edge cases to handle (disconnected nodes,\ncycles, weighted edges). You want to structure your workflow for efficient iterative refinement with Claude. What approach will most effectively\nenable progressive improvement across multiple iterations?",
    "options": {
      "A": "Have Claude extensively research the algorithm and create a detailed implementation plan using extended thinking, then implement the\ncomplete solution based on that plan.",
      "B": "Provide Claude with a reference implementation from documentation, then ask it to rewrite the code to match your codebase style and add\nthe required edge case handling, comparing outputs against the reference.",
      "C": "Provide Claude with a detailed natural language specification of the algorithm, including all requirements and edge cases. Review each\noutput manually and provide descriptive feedback on what behavior needs to change.",
      "D": "Write a test suite covering expected behavior, edge cases, and performance requirements before implementation. Ask Claude to write code\nthat passes the tests, then iterate by sharing test failures with each refinement request."
    },
    "correctAnswer": "D"
  },
  {
    "id": 56,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYou’ve documented API error handling conventions in a CLAUDE.md file at your project root, specifying that endpoint handlers should use a\ncustom ApiError class. After several sessions, you notice Claude Code sometimes follows these conventions and sometimes uses generic\ntry/catch blocks with string messages. The inconsistency appears random across different coding sessions. What’s the most efficient first\ndiagnostic step?",
    "options": {
      "A": "Add a more detailed code examples to your CLAUDE.md showing the exact ApiError usage pattern for different endpoint types.",
      "B": "Run /memory to check which memory files are loaded and verify your CLAUDE.md is included.",
      "C": "Search for conflicting instructions in ~/.claude/CLauDe.md or ~/.claude/rules/ that might override your project conventions.",
      "D": "Create path-specific rules in .claude/rules/handlers.md with YAML frontmatter scoping the error handling instructions to your API handler\nfiles."
    },
    "correctAnswer": "B"
  },
  {
    "id": 57,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYour team has connected a custom MCP server that provides DevOps workflow templates. The server exposes several MCP prompts (such as\ndeploy_checklist and incident_response) in addition to tools. How do these MCP prompts become accessible within Claude Code?",
    "options": {
      "A": "They are surfaced as @ -mentionable resources alongside files, fetched and attached to your message when referenced.",
      "B": "They are automatically prepended to every conversation as additional system-level context, influencing Claude’s behavior throughout the\nsession.",
      "C": "They are added to Claude Code’s tool registry alongside the server’s tools, invoked automatically by the model when relevant to the task.",
      "D": "They appear as slash commands (e.g., mcp_servername_deploy_checklist) that you can invoke, with arguments passed after the command\nname."
    },
    "correctAnswer": "D"
  },
  {
    "id": 58,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYou’re implementing a new payment processing module that must follow your project’s established patterns for database transactions, error\nhandling, and audit logging. You’ve identified three existing modules that exemplify these patterns: db_utils.py, error_handlers.py, and\naudit_logger.py. This is a one-off integration task – these patterns are well-documented in your team wiki and don’t need additional project-level\ndocumentation. What’s the most effective approach?",
    "options": {
      "A": "Add documentation of each pattern to your CLAUDE.md file, establishing them as project conventions that Claude will apply automatically.",
      "B": "Describe the patterns from the three modules in natural language in your prompt, explaining the transaction handling approach, error\nformat, and logging conventions Claude should follow.",
      "C": "Ask Claude to explore your codebase to find and understand the transaction, error handling, and logging patterns before generating the new\nmodule.",
      "D": "Use @ references to include the three modules directly in your prompt, giving Claude concrete code examples of the patterns to follow."
    },
    "correctAnswer": "D"
  },
  {
    "id": 59,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYour team is configuring MCP servers in Claude Code. You want to add a shared venue lookup server that all team members should have access\nto, and you personally want to add an experimental music playlist server that only you are testing. Which configuration approach correctly applies\nMCP server scopes?",
    "options": {
      "A": "Add both servers to your local ~/.claude.json",
      "B": "Add venue server to ~/.claude.json and playlist server to .mcp.json",
      "C": "Add venue server to .mcp.json and playlist server to ~/.claude.json.",
      "D": "Add both servers to the project-level .mcp.json file"
    },
    "correctAnswer": "C"
  },
  {
    "id": 60,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYour monorepo contains shared coding standards in /docs/standards/ : security-rules.md (for services handling user data), testing-petterns.md\n(for all packages), and api-conventions.md (for API-facing services). Your 15 packages are organized by feature domain ( /packages/auth/,\n/packages/billing/, /packages/notifications/ , etc.) without naming conventions indicating which handle user data or expose APIs. Package\nmaintainers are expected to configure their own local development settings, as they understand their package’s domain requirements. Currently,\nall package CLAUDE.md files duplicate all three standards, applying irrelevant guidance. What’s the most effective approach?",
    "options": {
      "A": "Create .claude/rules/ files for each standard with YAML frontmatter paths listing every package directory where that standard should apply.",
      "B": "Put all standards in the root CLAUDE.md with override instructions like “ignore security-rules.md when working in packages that don’t\nhandle user data.”",
      "C": "Create a shared-stendards.md that uses @imports to combine all three standards, then have each package’s CLAUDE.md import that\ncombined file.",
      "D": "Use @imports in each package’s CLAUDE.md to reference only the specific standard files relevant to that package, based on the\nmaintainer’s domain knowledge."
    },
    "correctAnswer": "D"
  },
  {
    "id": 61,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYour team has three requirements for Claude Code’s behavior in your project\n1. Claude must never modify files in the db/migrations/ directory\n2. Claude should prefer your custom logging module over console.log\n3. All TypeScript files must be auto-formatted with Prettier after every edit\nAll three are currently written as instructions in your project’s CLAUDE.md. During a complex refactoring session, a developer discovers that\nClaude edited a migration file, violating requirement #1. How should you restructure these requirements across Claude Code's configuration\nmechanisms?",
    "options": {
      "A": "Add Edit(./db/migrations/**) to permissions.deny in the project settings, keep the logging preference in CLAUDE.md, and add a\nPostToolUse hook on the Edit tool that runs Prettier on changed TypeScript files.",
      "B": "Move all three requirements into .claude/rules/ as path-scoped rules: one targeting db/migrations/** that forbids editing those files, and\nothers targeting **/*.ts for the logging convention and formatting instruction.",
      "C": "Rewrite all three requirements in CLAUDE.md using stronger directive language and add few-shot examples that demonstrate Claude\nrefusing to edit migration files and running Prettier after edits.",
      "D": "Configure hooks for all three: a PreToolUse hook script that blocks Edit calls targeting db/migrations/,a PreToolUse hook script that adds\nlogging convention context before edits, and a PostToolUse hook that runs Prettier after TypeScript edits."
    },
    "correctAnswer": "A"
  },
  {
    "id": 62,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYour team frequently migrates React components to Vue. You’ve written a step-by-step workflow for Claude Code to follow during each migration,\nand you want every developer on the team to invoke it by typing /migrate-component. The workflow should stay in sync as the team iterates on it.\nWhere should you place the skill file?",
    "options": {
      "A": "In ~/.claude/skills/migrate-component/SKILL.md on each developer’s machine",
      "B": "In .claude/skills/migrate-component/SKILL.md at the project root, committed to version control",
      "C": "In the project’s.claude/settings.json using a skillOverrides entry to register and define the workflow",
      "D": "As a detailed instruction block in the project’s root CLAUDE.md file"
    },
    "correctAnswer": "B"
  },
  {
    "id": 63,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYou’ve asked Claude to write a data migration script, but the initial output doesn’t correctly handle records with null values in required fields.\nWhat’s the most effective way to iterate toward a working solution?",
    "options": {
      "A": "Manually edit the generated code to fix the null handling, then continue working with Claude on other parts.",
      "B": "Add “think harder about edge cases” to your prompt and request a complete rewrite of the migration logic.",
      "C": "Describe the null value problem in detail and ask Claude to regenerate the entire script with improved edge case handling.",
      "D": "Provide a test case with example input containing null values and the expected output, then ask Claude to fix it."
    },
    "correctAnswer": "D"
  },
  {
    "id": 64,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYou’re implementing a caching layer for API responses to speed up the /products endpoint. You have a rough idea–Redis with a 5-minute TTL–but\nyou’re new to production caching and aren’t sure what other considerations a robust implementation requires. What’s the most effective way to\nstart your iterative workflow?",
    "options": {
      "A": "Start with a minimal request: “Add Redis caching to /products with 5-minute TTL.” Add features and fix issues through follow-up prompts as\nproblems surface during testing.",
      "B": "Write a specification with your known requirements and “TBD” markers for uncertain areas, having Claude propose solutions for each TBD\nas it implements.",
      "C": "Ask Claude to interview you about the caching requirements before implementing, surfacing considerations like invalidation strategies,\ncache layers, consistency guarantees, and failure modes.",
      "D": "Use plan mode to analyze the current/products endpoint implementation, then provide your caching requirements once Claude explains\nhow the existing code is structured."
    },
    "correctAnswer": "C"
  },
  {
    "id": 65,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYour team wants Claude to follow a detailed code review checklist (8 items covering API changes, test coverage, documentation, security, etc.)\nwhen reviewing pull requests. The team also uses Claude extensively for other tasks: writing new features, debugging production issues, and\ngenerating documentation. Currently, developers paste the checklist at the start of each review session. Which approach best addresses this\nworkflow need?",
    "options": {
      "A": "Create a /review slash command containing the checklist, invoked when starting reviews.",
      "B": "Create a dedicated review subagent with the checklist embedded in its configuration.",
      "C": "Configure plan mode as the default for code review sessions.",
      "D": "Add the checklist to the project’s CLAUDE.md file under a “Code Review” section."
    },
    "correctAnswer": "A"
  },
  {
    "id": 66,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nA critical bug is affecting production users. Error logs show exceptions in the OrderProcessing module with a clear stack trace pointing to a\nspecific function. You haven’t worked with this module before. What’s the most effective approach?\n",
    "options": {
      "A": "Start with direct execution to gather initial information, then switch to plan mode to design a comprehensive solution before implementing\nany changes.",
      "B": "Enter plan mode to explore the module’s architecture and dependencies before attempting any fixes.",
      "C": "Use plan mode to analyze the error in context of the module’s design, enumerate potential root causes, and prioritize fixes systematically.",
      "D": "Use direct execution to examine the stack trace, read the relevant code, and implement a fix once you identify the root cause."
    },
    "correctAnswer": "D"
  },
  {
    "id": 67,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nYour agent has analyzed a complex service module –reading 23 source files, tracing request flows, and identifying error handling patterns. A\ndeveloper wants to compare two testing strategies before committing to one: end-to-end tests with mocked external services vs. snapshot tests\ncapturing expected outputs. They need to independently develop both approaches to evaluate trade-offs. How should you manage the sessions?",
    "options": {
      "A": "Start two fresh sessions, having each re-read the relevant source files before beginning.",
      "B": "Resume the analysis session with fork_session enabled, creating a separate branch for each testing strategy.",
      "C": "Export the analysis session's key findings to a file, then create two new sessions that reference this file.",
      "D": "Continue in the original session, developing end-to-end tests first, then snapshot tests sequentially."
    },
    "correctAnswer": "B"
  },
  {
    "id": 68,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nAn engineer asks the agent to understand how the caching layer works before adding a new cache invalidation trigger. After initial Grep searches,\nthe agent has identified that caching logic spans 15 files including decorators, middleware, and service classes (~8,000 lines total). What’s the\nmost effective next step for building understanding while managing context constraints?",
    "options": {
      "A": "Use the Read tool to sequentially load all 15 files, building complete understanding across the full caching implementation.",
      "B": "Use Glob to find files matching common caching patterns (cache.py, caching/), prioritize the largest files by reading them first, then check\nsmaller files for gaps.",
      "C": "Analyze imports and class hierarchies to identify the base cache class, Read that file to understand the interface, then trace specific\ninvalidation implementations.",
      "D": "Use Grep to search for “invalidate” and “expire” patterns across all files, then Read only those specific line ranges with minimal surrounding\ncontext."
    },
    "correctAnswer": "C"
  },
  {
    "id": 69,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nAn engineer sees an unfamiliar error message “SYNC_CONFLICT: entity version mismatch detected” in production logs but doesn’t know which of\nthe 12 services in the codebase generates it. They ask the agent to help locate the source code. What exploration approach will most efficiently\nfind the responsible code?",
    "options": {
      "A": "Use Glob to find files in directories commonly associated with error handling (such as errors/, exceptions/,or handlers/) across all services,\nthen Read each matching file.",
      "B": "Read the project’s README and service configuration files to understand the architecture, then systematically Read source files in each\nservice directory.",
      "C": "Use Grep to search for distinctive text from the error message (like “SYNC_CONFLICT” or “entity version mismatch”), then Read the\nmatching files to understand context.",
      "D": "Use Grep to find all files that import the project’s error handling module, then Read those files to locate custom error definitions."
    },
    "correctAnswer": "C"
  },
  {
    "id": 70,
    "question": "After integrating a local MCP server providing code analysis tools (analyze_dependencies, find_dead_code, calculate _complexity), you verify the\nserver is healthy and tools appear in the tools/list response. However, you observe that the agent consistently uses Grep to search for import\nstatements instead of calling analyze_dependencies –even when users explicitly ask about “code dependencies.”\nExamining tool definitions reveals:\n• MCP: analyze_ dependencies – “Analyzes dependency graph”\n• Built-in: Grep – “Search file contents for a pattern using regular expressions. Returns matching lines with line numbers and surrounding context.”\nWhat's the most effective approach to improve the agent's selection of MCP tools?",
    "options": {
      "A": "Add routing instructions to the system prompt specifying that dependency-related questions should use MCP tools rather than Grep.",
      "B": "Remove Grep from available tools when the MCP server is connected to eliminate functional overlap.",
      "C": "Split analyze_dependencies into granular tools ( list_imports, resolve_transitive_deps, detect_circular_deps) so each has a focused purpose\nless likely to overlap with Grep.",
      "D": "Expand MCP tool descriptions to detail capabilities and outputs – e.g., “Builds dependency graph showing direct imports, transitive\ndependencies, and cycles.”"
    },
    "correctAnswer": "D"
  },
  {
    "id": 71,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nYour agent has spent 25 minutes exploring a game engine's rendering subsystem –reading shader code, buffer management, and frame\nsynchronization logic. An engineer now asks it to understand how the physics engine integrates with rendering for collision debug overlays. You\nnotice recent responses reference “typical rendering patterns” rather than the specific VulkanPipeline and FrameGraph classes it discovered\nearlier.\nWhat’s the most effective approach?",
    "options": {
      "A": "Continue in the current context with more targeted prompts referencing the specific classes by name.",
      "B": "Summarize key rendering findings, then spawn a sub-agent for physics exploration with that summary in its initial context.",
      "C": "Spawn a sub-agent to explore physics independently, then manually synthesize its findings with the rendering knowledge accumulated in\nthe main conversation.",
      "D": "Use /clear to reset context completely, then start fresh with physics exploration using file paths from the project's CLAUDE.md."
    },
    "correctAnswer": "B"
  },
  {
    "id": 72,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nYour codebase exploration tool stores session IDs to allow engineers to continue investigations across work sessions. An engineer spent an hour\nyesterday analyzing a legacy authentication module, building context about its architecture and dependencies. They want to continue today. The\nsession ID is valid, but version control shows 3 of the 12 files the agent previously read were modified overnight by a teammate's merge. What\napproach best balances efficiency and accuracy?",
    "options": {
      "A": "Start fresh session to ensure the agent works with current codebase state without stale assumptions",
      "B": "Resume the session and inform the agent which specific files changed for targeted re-analysis",
      "C": "Resume the session and immediately\nhave the agent re-read all 12 previously analyzed files",
      "D": "Resume the session without informing the agent about the changed files"
    },
    "correctAnswer": "B"
  },
  {
    "id": 73,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nYour code review assistant needs to analyze pull requests and provide feedback on three aspects: code style compliance, potential security\nissues, and documentation completeness. Each aspect requires reading files, running analysis tools, and generating a report section. The review\nprocess follows the same three-step workflow for every PR. Which task decomposition pattern is most appropriate for this workflow?",
    "options": {
      "A": "Routing – classify each PR by type (feature, bugfix, refactor) first, then route to different review prompts optimized for that category.",
      "B": "Prompt chaining – break the review into sequential steps where each aspect (style, security, documentation) is analyzed separately, with\noutputs combined in a final synthesis step.",
      "C": "Single comprehensive prompt – include all instructions in one prompt and let the model handle all three aspects simultaneously.",
      "D": "Orchestrator-workers – have a central LLM analyze each PR to dynamically determine which checks are needed, then delegate to\nspecialized worker LLMs for each identified subtask."
    },
    "correctAnswer": "B"
  },
  {
    "id": 74,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nAfter adding an MCP server with specialized code refactoring tools (extract_function, rename_variable, inline_function), You notice the agent still\nuses basic text manipulation via Write and Bash sed commands for refactoring tasks. The MCP server is connected and healthy. Examining the\nconfiguration, you find each MCP tool has a minimal description like “extract_function: Extracts a function from code.”\nWhat’s the most effective way to improve adoption of the MCP refactoring tools?",
    "options": {
      "A": "Implement a request classifier that detects refactoring intent and automatically routes those requests to the MCP server before the agent\nprocesses them.",
      "B": "Remove the Write tool from the agent’s configuration for refactoring sessions so it must use the MCP tools for code modifications.",
      "C": "Accept this as expected behavior since simpler tools like sed are more predictable than specialized refactoring tools.",
      "D": "Enhance the MCP tool descriptions to explain when each tool is preferable to text manipulation and clarify expected inputs and outputs."
    },
    "correctAnswer": "D"
  },
  {
    "id": 75,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers. A developer asks the agent to investigate why a specific API endpoint intermittently returns 500 errors. The codebase has 200+ files and the developer doesn't know which components are involved. The agent must trace the error through routing, middleware, business logic, and database\nlayers. What task decomposition approach would be most effective?\n",
    "options": {
      "A": "Have the agent dynamically generate investigation subtasks based on what it discovers at each step, adapting its exploration plan as new\ninformation about the error path emerges.",
      "B": "Have the agent first create a comprehensive plan mapping all code paths through the endpoint before beginning any file exploration or code\nreading.",
      "C": "Run parallel worker agents that simultaneously investigate all four layers, then synthesize their findings to identify where the error\noriginates.",
      "D": "Define a fixed sequence of investigation steps upfront – grep for error patterns, then read error handlers, then check database queries, then\nexamine middleware – executing each step regardless of intermediate findings."
    },
    "correctAnswer": "A"
  },
  {
    "id": 76,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nYour agent needs to insert a new helper function into the middle of a 150-line utility module, between two existing functions. The Edit tool fails\nbecause its old_string parameter cannot find unique text to match – the file has repetitive docstrings, variable names, and structural patterns.\nWhat's the most reliable way to complete this insertion?",
    "options": {
      "A": "Use Edit with an extremely long old_string capturing 30+ lines of context to guarantee uniqueness",
      "B": "Use Bash to append the function definition to the end of the file using heredoc syntax",
      "C": "Use Edit’s replace_all parameter to target a common pattern and embed the new function in the replacement text",
      "D": "Use Read to load the file, add the function at the appropriate location, then Write the updated file"
    },
    "correctAnswer": "D"
  },
  {
    "id": 77,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nAn engineer used the agent yesterday to analyze a legacy authentication module, identifying two distinct refactoring approaches: extracting a\nmicroservice versus refactoring in-place. Today, they want to explore both approaches in depth – having the agent propose specific code changes\nfor each – before deciding which to implement. What’s the most effective way to structure this exploration?",
    "options": {
      "A": "Start two fresh sessions, manually providing a summary of yesterday’s analysis findings to establish context.",
      "B": "Resume yesterday’s session and explore both approaches sequentially within the same conversation thread.",
      "C": "Resume yesterday’s session to explore the first approach, then start a new session for the second, manually recreating the original context.",
      "D": "Use fork_session to create two branches from yesterday’s analysis, exploring one approach in each fork."
    },
    "correctAnswer": "D"
  },
  {
    "id": 78,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nAn engineer asks your agent to identify untested code paths in a legacy payment processing module spanning 45 files. After reading the first 8\nsource files, the agent's responses are becoming noticeably less accurate – it's forgetting previously discussed code patterns and hasn't yet\nlocated all test files or traced critical payment flows. What’s the most effective approach to complete this investigation?",
    "options": {
      "A": "Switch to using Grep to search for specific function names instead of reading full files, reducing the content loaded into context for\nremaining exploration.",
      "B": "Spawn subagents to investigate specific questions (e.g., “find all test files for payment processing,” “trace refund flow dependencies”) while\nthe main agent coordinates findings and preserves high-level understanding.",
      "C": "Document all current findings in a summary report, clear context completely, then use that report as the sole reference for continuing the\ninvestigation.",
      "D": "Clear context with /clear, then selectively re-read only the most critical files discovered so far, writing key findings to a scratchpad file that\npersists between context resets."
    },
    "correctAnswer": "B"
  },
  {
    "id": 79,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nDuring testing, you observe that in extended exploration sessions (30+ minutes), the agent starts giving inconsistent answers about code\nstructure it discussed earlier. Engineers report having to repeat context about modules they’ve already explored. What's the most effective\napproach to address this?",
    "options": {
      "A": "Implement automatic context clearing every 15 minutes to ensure the agent starts with fresh, uncontaminated context.",
      "B": "Switch to a higher-capacity model tier to provide more context window space for accumulated exploration data.",
      "C": "Create summaries of all source files before exploration begins, loading only these compressed representations into context.",
      "D": "Have the agent maintain a scratchpad file that records key findings, referencing it for subsequent questions."
    },
    "correctAnswer": "D"
  },
  {
    "id": 80,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nAn engineer submits two requests:\n• Request A: “Rename the getUserData function to fetchUserProfile everywhere it’s used.”\n• Request B: “Improve error handling throughout the data processing module – add try/catch blocks, meaningful error messages, and ensure\nfailures don’t silently corrupt data.”\nFor which request does specifying an explicit multi-phase workflow (such as analyze –> propose –> implement with review) most improve\noutcome quality?",
    "options": {
      "A": "Neither request benefits significantly",
      "B": "Request A, the function rename task",
      "C": "Both requests benefit equally",
      "D": "Request B, the error handling task"
    },
    "correctAnswer": "D"
  },
  {
    "id": 81,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nAn engineer asks the agent to find all files in the monorepo that import the @company/auth package to understand how authentication is used\nacross services. Which built-in tool is most appropriate for this task?",
    "options": {
      "A": "Read, starting with package.json files to trace dependency declarations",
      "B": "Glob, to find files with “auth” in their filename or path",
      "C": "Grep, to search for the import statement pattern across file contents",
      "D": "Bash, to execute find. –type d –name “*auth*” and explore matching directories"
    },
    "correctAnswer": "C"
  },
  {
    "id": 82,
    "question": "You are building a multi-agent research system using the Claude Agent SDK. A coordinator agent delegates to specialized subagents: one\nsearches the web, one analyzes documents, one synthesizes findings, and one generates reports. The system researches topics and produces\ncomprehensive, cited reports.\nWhen researching “renewable energy adoption,” the web search agent returns recent statistics (2024: 35% adoption) while the document analysis\nagent extracts data from internal reports (2021: 18% adoption). The synthesis agent incorrectly flags these as contradictory sources rather than\nrecognizing the data shows growth over time. What change would best enable the synthesis agent to correctly interpret such temporal\ndifferences?",
    "options": {
      "A": "Instruct the synthesis agent to always treat the most recent data as authoritative and place older findings in a separate historical appendix.",
      "B": "Add a conflict resolution agent that automatically discards older data when newer data exists for the same metric.",
      "C": "Require subagents to include publication or data collection dates in their structured outputs.",
      "D": "Configure the web search agent to only return results from the past 6 months."
    },
    "correctAnswer": "C"
  },
  {
    "id": 83,
    "question": "You are building a multi-agent research system using the Claude Agent SDK. A coordinator agent delegates to specialized subagents: one\nsearches the web, one analyzes documents, one synthesizes findings, and one generates reports. The system researches topics and produces\ncomprehensive, cited reports.\nIn production, you observe that simple fact-checking queries (e.g., “What year was the Paris Climate Agreement signed?”) traverse all four\nsubagents sequentially, consuming 40+ seconds and significant tokens per query. Complex comparative research benefits from the full pipeline.\nYour query distribution is diverse and evolving as users discover new applications. What’s the most effective approach to optimize for varying\nquery complexity?",
    "options": {
      "A": "Create a fast-path for factual questions that bypasses subagents entirely, routing all other queries through the complete pipeline to ensure\nresearch thoroughness.",
      "B": "Implement pattern-based routing that categorizes queries by structure (single-fact vs. comparative vs. analytical) and maps each category\nto a predefined subagent combination.",
      "C": "Train a query complexity classifier on labeled historical data to predict optimal subagent combinations, retraining periodically as query\npatterns evolve.",
      "D": "Have the coordinator analyze each query and dynamically decide which subagents to invoke based on its assessment of query\nrequirements."
    },
    "correctAnswer": "D"
  },
  {
    "id": 84,
    "question": "You are building a multi-agent research system using the Claude Agent SDK. A coordinator agent delegates to specialized subagents: one\nsearches the web, one analyzes documents, one synthesizes findings, and one generates reports. The system researches topics and produces\ncomprehensive, cited reports.\nWhen analyzing complex legal cases that cite multiple precedents, the document analysis subagent processes each sequentially. A landmark\ncase citing 12 precedents takes over 3 minutes to analyze completely. What’s the most effective way to reduce this latency while preserving the\ncoordinator’s ability to monitor and debug the system?",
    "options": {
      "A": "Create a recursive agent hierarchy where analysis agents subdivide work among child agents until reaching single-precedent granularity",
      "B": "Have the coordinator spawn parallel document analysis subagents, each handling a subset of precedents, then aggregate results before\nsynthesis",
      "C": "Enable the document analysis subagent to spawn its own specialized subagents dynamically when it encounters cases with many citations",
      "D": "Implement a message queue where precedent analysis tasks are processed asynchronously by a pool of worker agents"
    },
    "correctAnswer": "B"
  },
  {
    "id": 85,
    "question": "You are building a multi-agent research system using the Claude Agent SDK. A coordinator agent delegates to specialized subagents: one\nsearches the web, one analyzes documents, one synthesizes findings, and one generates reports. The system researches topics and produces comprehensive, cited reports. \nA user is expanding the research system beyond its single web search agent by adding specialized data sources. They add a financial API agent\nthat returns structured JSON with revenue, margins, and growth rates; a news monitoring agent that returns prose summaries of recent\ndevelopments; and a patent analysis agent that returns structured lists of technology areas. The synthesis agent combines these into executive\nbriefings. Currently, it converts everything to bullet points, causing financial comparisons to lose tabular clarity and news summaries to lose\nnarrative flow. What change would most improve briefing quality?\n",
    "options": {
      "A": "Update the synthesis agent to render each content type appropriately – financial data as tables, news as prose",
      "B": "Standardize all subagent outputs to prose summaries with inline citations",
      "C": "Standardize all subagent outputs to JSON with fields for claim, evidence, source, and confidence",
      "D": "Add a format conversion layer between subagents and synthesis that transforms all outputs to a common intermediate representation"
    },
    "correctAnswer": "A"
  },
  {
    "id": 86,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYou've asked Claude Code to build a PDF report generation feature. The initial implementation queries the database correctly, but the output has\nformatting issues: table columns are too narrow causing content truncation, dates display without proper formatting, and page break handling is\nincorrect. You've noticed these issues interact – changing column widths affects how dates render, and page breaks depend on content height.\nWhat's the most effective approach for iterating toward a working solution?",
    "options": {
      "A": "Show Claude an example of a correctly formatted report and ask it to match that output, rather than listing the specific technical issues.",
      "B": "Address the column width issue first with specific measurements, verify it works, then fix date formatting within the corrected columns,\nthen adjust page breaks – testing after each change.",
      "C": "Provide all three issues in a single detailed message with exact specifications for each, allowing Claude to address them together in one\nupdate.",
      "D": "Start fresh with a detailed prompt specifying all formatting requirements upfront."
    },
    "correctAnswer": "B"
  },
  {
    "id": 87,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and\ndocumentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and\nunderstand when to use plan mode vs direct execution.\nYou're tasked with adding real-time updates to the application. This could be implemented using WebSockets, Server-Sent Events, or polling, each\nwith different complexity, browser support, and infrastructure requirements.\nWhat's the most effective way to begin this task?",
    "options": {
      "A": "Use direct execution with a prompt asking Claude to analyze all approaches and implement the one it determines is best.",
      "B": "Use direct execution to implement polling first, then evaluate whether to upgrade to WebSockets later.",
      "C": "Enter plan mode to explore the architecture, evaluate trade-offs, and present options for team approval before implementing.",
      "D": "Start direct execution with WebSockets, then refactor if infrastructure issues arise."
    },
    "correctAnswer": "C"
  },
  {
    "id": 88,
    "question": "You are using Claude Code to accelerate software development. Your team uses it for code generation, refactoring, debugging, and documentation. You need to integrate it into your development workflow with custom slash commands, CLAUDE.md configurations, and understand when to use plan mode vs direct execution.\nA security audit requires updating your authentication library from v2 to v3. The migration guide documents breaking changes: `authenticate()` now returns a Promise instead of accepting a callback, the `User` type has restructured fields, and three deprecated methods were removed. Grep\nshows the library is imported in 45 files across several modules.\nWhat's the most effective approach?\n",
    "options": {
      "A": "Update the dependency version, run the test suite, and use Claude Code to fix each failure as it appears.",
      "B": "Paste the migration guide's breaking changes into your prompt and use direct execution to update all usages across the 45 files.",
      "C": "Create a custom slash command encapsulating the migration transformations, then execute it against each file without prior codebase\nexploration.",
      "D": "Enter plan mode to explore library usage across modules, map affected code paths, then create a migration strategy before implementing."
    },
    "correctAnswer": "D"
  },
  {
    "id": 89,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nAn engineer asks your agent to add comprehensive tests to a legacy codebase with 200 files and minimal existing test coverage. The engineer\nhasn't specified which modules to prioritize.\nHow should the agent decompose this open-ended task?",
    "options": {
      "A": "Start writing tests for the first module alphabetically, using test failures and imports to discover related files organically.",
      "B": "Use Glob and Grep to map codebase structure, identify heavily-coupled modules, create a prioritized plan for high-impact areas, and revise\nas dependencies are discovered.",
      "C": "Systematically read all 200 files to create a complete function inventory before writing any tests, ensuring the testing plan accounts for\nevery function before beginning.",
      "D": "Create a fixed testing schedule upfront based on directory structure, allocating equal effort to each top-level directory regardless of code\ncomplexity or business importance."
    },
    "correctAnswer": "B"
  },
  {
    "id": 90,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nYou've configured your Claude agent with three MCP servers: one for git operations, one for Jira ticket management, and one for documentation\nsearch.\nWhen a user asks the agent to \"create a branch for JIRA-123 and add documentation links to the ticket,\" how does the agent access tools across\nthese servers?",
    "options": {
      "A": "Tools from all configured MCP servers are discovered at connection time and available simultaneously to the agent.",
      "B": "The agent automatically selects the most relevant server based on the request and loads only that server's tools.",
      "C": "The agent queries each server sequentially to determine which handles each tool, routing calls based on tool name prefixes.",
      "D": "You must specify which MCP server to use for each turn, and the agent can only access one server's tools at a time."
    },
    "correctAnswer": "A"
  },
  {
    "id": 91,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nAn engineer's exploration subagent spent 30 minutes analyzing a legacy payment system, reading 47 files and documenting data flows. The\nsession was interrupted when the engineer's connection dropped. While away, a teammate merged a PR that renamed two utility functions. The\nengineer wants to continue the same exploration.\nWhat's the most effective approach?",
    "options": {
      "A": "Resume the subagent from its previous transcript without mentioning the changes – the architecture understanding remains valid.",
      "B": "Launch a fresh subagent and include the prior transcript in the initial prompt for context.",
      "C": "Launch a fresh subagent with a summary of prior findings.",
      "D": "Resume the subagent from its previous transcript and inform it about the renamed functions."
    },
    "correctAnswer": "D"
  },
  {
    "id": 92,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nAn engineer used Claude Code yesterday to investigate authentication flows in a legacy monolith, building up significant context over a 2-hour\nsession. Today she wants to continue that specific investigation. She's worked on three other codebases since then and knows the session was\nnamed \"auth-deep-dive\".\nHow should she resume?",
    "options": {
      "A": "Use `--resume auth-deep-dive` to load that specific session by name",
      "B": "Use `--continue` to pick up where the most recent conversation left off",
      "C": "Start fresh and re-read the same files",
      "D": "Use `--session-id` with the UUID from yesterday's session transcript file"
    },
    "correctAnswer": "A"
  },
  {
    "id": 93,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nAn engineer asks the agent to find all callers of a function before removing it. The function is defined in a core library but is also exposed through\nwrapper modules that rename the function for domain-specific use (e.g., `calculateTax` in the library becomes `computeOrderTax` in the orders\nmodule).\nWhat exploration strategy will most reliably identify all callers?",
    "options": {
      "A": "Search for the function name in project documentation to understand intended usage patterns and navigate to documented integration\npoints.",
      "B": "Use Grep to find all files that import from the library or wrapper modules, then read each file to check whether it uses the function.",
      "C": "Use Grep to search for the function's original name across the codebase.",
      "D": "Read the library and wrapper modules to identify all exposed names for the function, then Grep for each name across the codebase."
    },
    "correctAnswer": "D"
  },
  {
    "id": 94,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour extraction pipeline processes restaurant menus and must output structured JSON with fields for item names, descriptions, prices, and\ndietary tags. Some menus use inconsistent formatting – prices as \"$12\" vs \"12.00\", dietary info as icons vs text.\nWhat's the most reliable approach?",
    "options": {
      "A": "Define a strict output schema and include format normalization rules in your prompt.",
      "B": "Extract data as-is and normalize formats in post-processing code after Claude returns.",
      "C": "Use separate extraction calls for each field to ensure consistent handling of each type.",
      "D": "Request multiple extraction attempts per document and select the most common format."
    },
    "correctAnswer": "A"
  },
  {
    "id": 95,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour system has been operating with 100% human review for 3 months. Analysis shows that extractions with model confidence ≥90% have 97%\naccuracy overall. To reduce reviewer workload, you plan to automate high-confidence extractions.\nBefore deploying, what validation step is most critical?",
    "options": {
      "A": "Verify that 97% accuracy meets requirements for all downstream systems that consume the extracted data.",
      "B": "Analyze accuracy by document type and field to verify high-confidence extractions perform consistently across all segments, not just in\naggregate.",
      "C": "Compare accuracy at different confidence thresholds (85%, 90%, 96%) to find the optimal cutoff that maximizes automation while\nminimizing errors.",
      "D": "Run a two-week pilot routing 25% of high-confidence extractions directly to downstream systems and monitor error reports."
    },
    "correctAnswer": "B"
  },
  {
    "id": 96,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour schema includes a `skills: string[]` field. Production monitoring reveals three consistency issues: (1) compound phrases like \"Python and\nSQL\" are sometimes kept as one entry, sometimes split; (2) implied but unstated skills occasionally appear in extractions; (3) similar documents\nproduce wildly different array lengths (5-10 vs 40+ entries). Your prompt currently says \"Extract all skills mentioned.\"\nWhat's the most effective improvement?",
    "options": {
      "A": "Add few-shot examples demonstrating compound phrase handling, explicit mention criteria, and appropriate entry granularity.",
      "B": "Add post-extraction normalization that maps skills to a canonical taxonomy and deduplicates similar entries.",
      "C": "Enrich the schema to `{skill: string, confidence: float, source_quote: string}[]` to capture extraction metadata.",
      "D": "Add constraints: \"Extract 10-20 skills maximum, one skill per entry, only explicitly named skills.\""
    },
    "correctAnswer": "A"
  },
  {
    "id": 97,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour system extracts event metadata (date, location, organizer, attendee_count) from news articles using a JSON schema with all nullable fields.\nDuring evaluation, you observe the model frequently generates plausible but incorrect values for fields not mentioned in the article – for example,\noutputting \"500\" for attendee_count when the source contains no attendance information.\nWhat's the most effective way to reduce these false extractions?",
    "options": {
      "A": "Add prompt instructions to return null for any field where information is not directly stated in the source.",
      "B": "Make all schema fields required (non-nullable) with strict validation rules to ensure the model only outputs verifiable data.",
      "C": "Add a post-processing step using a second LLM call to verify each extracted value exists in the source document.",
      "D": "Upgrade to a more capable model tier with improved instruction-following to reduce hallucination tendencies."
    },
    "correctAnswer": "A"
  },
  {
    "id": 98,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour system has been running for 3 weeks and human reviewers have corrected 847 extractions. Analysis reveals a recurring pattern: when\nrecipes use informal measurements like \"a handful\" or \"a splash,\" the model either invents specific amounts or leaves fields empty – accounting\nfor 23% of all corrections.\nHow should you use this feedback to improve extraction accuracy?",
    "options": {
      "A": "Update your JSON schema to add a \"measurement_type\" enum field (precise/informal).",
      "B": "Implement a post-processing layer that uses pattern matching to detect informal measurement phrases in source text and automatically\npopulate values when the extraction is empty.",
      "C": "Add few-shot examples to your prompt demonstrating correct handling of informal measurements – extracting them verbatim rather than\nconverting or omitting them.",
      "D": "Fine-tune the model on the 847 corrected extractions."
    },
    "correctAnswer": "C"
  },
  {
    "id": 99,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour pipeline uses a tool called `extract_metadata` with a JSON schema for paper details. You've also defined `lookup_citations` and `verify_doi`\ntools for enrichment. During testing, you notice that when users include requests like \"extract the metadata and tell me how cited it is,\" Claude\nsometimes calls `lookup_citations` first, which fails because it needs the DOI that `extract_metadata` would provide.\nWhat's the most effective way to ensure structured metadata extraction happens first?",
    "options": {
      "A": "Set `tool_choice` to `{\"type\": \"tool\", \"name\": \"extract_metadata\"}` for every API call in the pipeline, ensuring Claude always extracts\nmetadata before any enrichment can occur.",
      "B": "Set `tool_choice` to `{\"type\": \"tool\", \"name\": \"extract_metadata\"}` and process the enrichment requests in subsequent turns after receiving\nthe extracted metadata.",
      "C": "Set `tool_choice` to `\"auto\"` and reorder the tool definitions so `extract_metadata` appears first in the tools array, since Claude prioritizes\nearlier-listed tools.",
      "D": "Set `tool_choice` to `\"any\"` so Claude must use a tool, combined with system prompt instructions prioritizing `extract_metadata`."
    },
    "correctAnswer": "B"
  },
  {
    "id": 100,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nTesting reveals that when source documents are missing certain specifications, the model fabricates plausible-sounding values to satisfy your\nschema's required fields. For example, a document mentioning only dimensions receives a fabricated \"weight: 2.3 kg\" in the extraction output.\nWhat schema design change most effectively addresses this hallucination behavior?",
    "options": {
      "A": "Change fields that may not exist in source documents from required to optional, allowing the model to omit them",
      "B": "Add explicit instructions to the prompt stating \"only extract information explicitly stated in the document; use placeholder text for missing\nvalues\"",
      "C": "Add a \"confidence\" field alongside each specification where the model self-reports its certainty, then filter out low-confidence extractions",
      "D": "Implement semantic validation that verifies each extracted value appears in or can be inferred from the source document text"
    },
    "correctAnswer": "A"
  },
  {
    "id": 101,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour extraction pipeline validates outputs against JSON schemas, but you need to implement human review given limited reviewer capacity (they\ncan handle approximately 5% of total extraction volume).\nWhat's the most effective basis for selecting which extractions to route for human review?",
    "options": {
      "A": "Randomly sample 5% of extractions for review.",
      "B": "Route extractions where the model indicates low confidence or where source documents contain ambiguous or contradictory information.",
      "C": "Route extractions for review only when downstream systems report data quality issues or processing failures.",
      "D": "Route extractions containing specific high-priority entity types (e.g., financial figures, dates) for human review, regardless of extraction\nconfidence."
    },
    "correctAnswer": "B"
  },
  {
    "id": 102,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nThe system needs to extract candidate information (name, contact details, skills, work experience, education) from uploaded resumes. The\nextracted data must strictly conform to a predefined JSON schema, as missing required fields or incorrect data types will cause downstream\nvalidation failures.\nWhat is the most reliable approach to ensure Claude's output consistently matches the schema?",
    "options": {
      "A": "Make two separate API calls – first extracting information as text, then asking Claude to format that text as JSON.",
      "B": "Define a tool with an input schema matching your required JSON structure and extract the data from Claude's tool_use response.",
      "C": "Parse Claude's text response with regex patterns to extract JSON objects, using retry logic for malformed responses.",
      "D": "Include detailed JSON formatting instructions and a template example in the system prompt, asking Claude to output only valid JSON."
    },
    "correctAnswer": "B"
  },
  {
    "id": 103,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nThe system routes documents with extraction confidence below 85% to human review. A quarterly audit reveals that 12% of high-confidence\nextractions (≥85%) also contain errors – cases where the model finds plausible-but-incorrect values. Error sources vary: comparison tables\nshowing competitor specs, appendices referencing different product variants, and ambiguous phrasing the model misinterprets. You need a\nsustainable strategy to catch these high-confidence errors and measure whether improvements reduce the error rate over time.\nWhat approach is most effective?",
    "options": {
      "A": "Add a verification pass that re-extracts from each high-confidence document, flagging cases where the two extraction attempts produce\ndifferent results",
      "B": "Lower the confidence threshold from 85% to 70%, routing a larger volume of extractions to human review.",
      "C": "Implement stratified random sampling reviewing a fixed percentage of high-confidence extractions weekly, enabling error rate measurement\nand novel pattern detection.",
      "D": "Implement heuristic rules that flag documents containing comparison tables or appendices for review regardless of confidence score."
    },
    "correctAnswer": "C"
  },
  {
    "id": 104,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour extraction pipeline processes invoices and extracts line items, subtotals, tax amounts, and grand totals. During evaluation, you discover that\nin 18% of extractions, the sum of extracted line item amounts doesn't match the extracted grand total – sometimes due to OCR errors in the\nsource document, sometimes due to extraction mistakes by the model. Downstream accounting systems reject records with mismatched totals.\nWhat's the most effective approach to improve extraction reliability?",
    "options": {
      "A": "Add few-shot examples demonstrating invoices where extracted line items sum correctly to the stated total, encouraging the model to\nproduce mathematically consistent extractions.",
      "B": "Add a \"calculated-total\" field where the model sums extracted line items alongside a \"stated_total\" field. Flag records for human review\nwhen values differ.",
      "C": "Extract line items and totals independently, then use a separate validation model to reconcile discrepancies by determining which extracted\nvalues are most likely correct.",
      "D": "Implement post-processing that automatically adjusts line item amounts proportionally when their sum doesn't match the stated total."
    },
    "correctAnswer": "B"
  },
  {
    "id": 105,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour extraction pipeline processes contracts that frequently include amendments. When a contract contains both original terms and later\namendments (e g., original clause specifies \"30-day payment terms\" while Amendment 1 changes this to \"45 days\"), the model inconsistently\nextracts one value or the other with no indication of which applies.\nWhat's the most effective approach to improve extraction accuracy for documents with amendments?",
    "options": {
      "A": "Preprocess documents with a classifier that identifies and removes superseded sections before the main extraction step.",
      "B": "Implement post-extraction validation using pattern matching to detect amendments and flag those extractions for manual review",
      "C": "Redesign the schema so amended fields capture multiple values, each with source location and effective date.",
      "D": "Add prompt instructions to always extract the most recent amendment value and ignore superseded original terms."
    },
    "correctAnswer": "C"
  },
  {
    "id": 106,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nMonitoring shows 12% of extractions fail Pydantic validation with specific errors like \"expected float for quantity, got '2 to 3'\". Retrying these\nrequests without modification produces identical failures.\nWhat's the most effective approach to recover from these validation failures?",
    "options": {
      "A": "Send a follow-up request including the validation error, asking the model to correct its output",
      "B": "Implement a secondary pipeline using a larger model tier to reprocess documents that fail validation",
      "C": "Pre-process source documents to standardize problematic formats before sending them for extraction",
      "D": "Set temperature to 0 to eliminate output variability and ensure consistent formatting"
    },
    "correctAnswer": "A"
  },
  {
    "id": 107,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour system must extract event details from calendar invitations and output JSON that strictly conforms to a schema with fields for title, date,\ntime, location, and attendees. Downstream systems reject any malformed or non-conformant JSON.\nWhat approach provides the most reliable schema compliance?",
    "options": {
      "A": "Include detailed JSON formatting instructions and the target schema in your prompt, then parse Claude's text response as JSON.",
      "B": "Define a tool with your target schema as input parameters and have Claude call it with the extracted data.",
      "C": "Append instructions like \"Output only valid JSON matching the schema exactly\" and implement retry logic to re-prompt when JSON parsing\nfails.",
      "D": "Pre-fill Claude's response with an opening brace to force JSON output, then complete and parse the response."
    },
    "correctAnswer": "B"
  },
  {
    "id": 108,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour extraction uses tool use with a JSON schema where `property_type` is defined as an enum: `['house', 'apartment', 'condo', 'townhouse']`. After\ndeployment, 8% of extractions fail schema validation. Investigation reveals listings mention many uncommon property types – \"studio\", \"loft\",\n\"duplex\", \"mobile home\", \"tiny house\", \"converted warehouse\" – and new types continue appearing regularly.\nWhat's the most effective long-term solution?",
    "options": {
      "A": "Continuously expand the enum to include newly observed property types and add monitoring for additional edge cases.",
      "B": "Change `property_type` from an enum to a free-form string and implement a normalization step in post-processing.",
      "C": "Add an \"other\" value to your enum with a separate `property_type_detail` string field for specifics when \"other\" is selected.",
      "D": "Add few-shot examples to your prompt demonstrating how to map unexpected property types to the closest existing enum value."
    },
    "correctAnswer": "C"
  },
  {
    "id": 109,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour extraction system uses tool_use with a JSON schema containing 12 fields and detailed descriptions, totaling approximately 2,500 tokens for\nthe complete tool definition. Processing documents under 150K tokens yields 98% accuracy. For documents between 175-190K tokens, accuracy\ndrops to 71%, with information from the final third consistently missed. The model's context window is 200K tokens.\nWhat is the most likely cause?",
    "options": {
      "A": "The model distributes attention proportionally across input length, causing fields mentioned only once near the document's end to receive\ninsufficient processing focus.",
      "B": "Very long documents exceed the model's effective attention span regardless of context limits, causing accuracy degradation for content\nfarther from the prompt instructions.",
      "C": "Schemas exceeding 8-10 fields increase decision complexity during parameter generation, reducing extraction accuracy independent of\ndocument length.",
      "D": "Tool definitions consume input context tokens. Combined with system prompts and document content, the total approaches the context\nlimit, degrading end-of-document processing."
    },
    "correctAnswer": "D"
  },
  {
    "id": 110,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nAfter your daily batch of 10,000 documents completes, 300 documents (3%) failed with \"context_length_exceeded\" errors. The results file\nidentifies each failure by custom_id.\nWhat's the most cost-effective approach to process these failures?",
    "options": {
      "A": "Resubmit only the 300 failed documents after chunking them into smaller pieces, then combine the partial extractions",
      "B": "Reprocess the entire batch with prompt caching enabled to reduce the cost of retrying requests with identical system prompts",
      "C": "Increase the max_tokens parameter for the 300 failed documents and resubmit them in a new batch",
      "D": "Resubmit the entire 10,000 document batch using a model tier with a larger context window"
    },
    "correctAnswer": "A"
  },
  {
    "id": 111,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour extraction system processes two document types: standard monthly reports (archived after processing) and urgent exception reports (must\ntrigger business alerts within 30 minutes of receipt). Both use the same JSON schema. You want to minimize API costs while meeting latency\nrequirements.\nHow should you architect the processing pipeline?",
    "options": {
      "A": "Submit all documents to the Batch API with custom_ids for tracking. When results arrive, immediately process urgent documents and\ntrigger delayed alerts for exceptions.",
      "B": "Queue all documents and submit hourly batches, flagging urgent documents for expedited handling when batch results return.",
      "C": "Submit all documents to the real-time Messages API to ensure consistent processing latency across document types.",
      "D": "Route standard reports to the Batch API for 50% cost savings, and route urgent exception reports to the real-time Messages API."
    },
    "correctAnswer": "D"
  },
  {
    "id": 112,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nYour extraction system parses e-commerce product descriptions to extract specifications like dimensions, weight, and materials into JSON.\nDespite having a well-defined schema, the model inconsistently extracts the \"materials\" field – sometimes returning \"cotton blend\", other times\n\"Cotton/Polyester mix\", and occasionally omitting the field when material information is clearly present in the source.\nWhat's the most effective way to improve extraction consistency?",
    "options": {
      "A": "Add few-shot examples showing 2-3 complete input-output pairs with standardized material description formats",
      "B": "Switch to a more capable model tier since inconsistent extraction indicates insufficient model capability",
      "C": "Make the \"materials\" field required instead of optional in the schema to force the model to always extract a value",
      "D": "Set temperature to 0 to eliminate randomness and ensure deterministic outputs"
    },
    "correctAnswer": "A"
  },
  {
    "id": 113,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nAfter implementing tool use with strict schema definitions, JSON syntax errors are eliminated, but 5% of extractions still have valid JSON with\nempty arrays or null values for required fields like citations and methodology. Spot-checking reveals that source documents contain this\ninformation, but in varied formats – inline citations vs. bibliographies, methodology sections vs. details embedded in introductions.\nWhat's the most effective way to address these failures?",
    "options": {
      "A": "Build a regex-based post-processing layer that scans source documents for citation patterns and methodology keywords, populating empty\nfields when the model fails to extract.",
      "B": "Implement retry logic that re-sends requests when validation detects empty required fields.",
      "C": "Add few-shot examples demonstrating extractions from documents with varied structures – showing how to identify citations in different\nformats and locate methodology details across section types.",
      "D": "Modify your schema to make citations and methodology optional, and flag incomplete records for manual review rather than failing\nvalidation."
    },
    "correctAnswer": "C"
  },
  {
    "id": 114,
    "question": "You are building a structured data extraction system using Claude. The system extracts information from unstructured documents, validates the\noutput using JavaScript Object Notation (JSON) schemas, and maintains high accuracy. It must handle edge cases gracefully and integrate with\ndownstream systems.\nAfter deployment, you find that 12% of extractions contain semantic errors that pass JSON schema validation (e.g., a duration like \"30 minutes\"\nincorrectly placed in an ingredient quantity field). Human reviewers have capacity to check only 20% of extractions.\nWhich approach most effectively allocates reviewer attention?",
    "options": {
      "A": "Prioritize review of all extractions where required fields are empty or explicitly marked as not found.",
      "B": "Have the model output field-level confidence scores, then calibrate review thresholds using a labeled validation set.",
      "C": "Review all extractions from documents with formatting anomalies such as unusual layouts or mixed content types.",
      "D": "Randomly sample 20% of extractions for review, using corrections to track accuracy and identify error patterns."
    },
    "correctAnswer": "B"
  },
  {
    "id": 115,
    "question": "You are building a multi-agent research system using the Claude Agent SDK. A coordinator agent delegates to specialized subagents: one\nsearches the web, one analyzes documents, one synthesizes findings, and one generates reports. The system researches topics and produces\ncomprehensive, cited reports.\nProduction monitoring shows the research phase takes longer than expected. Analysis reveals the coordinator invokes the web search subagent,\nwaits for its response, then invokes the document analysis subagent and waits again. These tasks are independent – neither requires the other's\noutput.\nHow should you modify the system to run these subagents concurrently?",
    "options": {
      "A": "Create an async orchestration layer outside the agent that spawns parallel threads, each running a separate coordinator-subagent pair, then\naggregates results.",
      "B": "Add detailed instructions to the coordinator's system prompt explaining the performance benefits of parallel execution and requesting it\ninvoke both subagents at the same time.",
      "C": "Switch both subagents to use a Haiku-tier model instead of Sonnet to reduce their individual execution time.",
      "D": "Structure the coordinator to emit both Task tool calls (for web search and document analysis) in a single response message rather than\nacross separate conversation turns."
    },
    "correctAnswer": "D"
  },
  {
    "id": 116,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nYour CI pipeline performs security-focused code reviews on approximately 50 PRs daily, currently costing $150/day using the synchronous API.\nReviews are non-blocking – developers merge after tests pass and address findings in follow-up commits. You're evaluating the Message Batches\nAPI for its 50% cost reduction.\nWhat factor most determines whether batch processing is appropriate for this use case?",
    "options": {
      "A": "Whether review feedback arriving up to 24 hours after PR creation remains actionable.",
      "B": "Whether your result processing can handle reviews arriving in a different order than submitted.",
      "C": "Whether you can structure each review as a single request without multi-turn refinement.",
      "D": "Whether reducing per-review latency from 30-60 seconds to near-instant matters for your workflow."
    },
    "correctAnswer": "A"
  },
  {
    "id": 117,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nYour pipeline runs: ``` PROMPT=\"You are a code reviewer.\"\nPROMPT=\"$PROMPT Analyze the provided diff\"\nPROMPT=\"$PROMPT for bugs, security issues,\"\nPROMPT=\"$PROMPT and style violations.\" claude -p \\ -- dangerously-skip-permissions \\ --system-prompt \"$PROMPT\" \\ < diff.txt``` The reviews\ncomplete and return feedback, but Claude only comments on the piped diff text – it never reads surrounding files in the checked-out repository to\nunderstand broader context, even when the diff modifies a function called by many other modules.\nWhich change to the invocation will cause Claude to read related files in the repository while still applying your custom review instructions?",
    "options": {
      "A": "Replace `--system-prompt` with `--append-system-prompt` so your review instructions are added to Claude Code's default prompt instead of\noverwriting the built-in guidance for using file-reading and code navigation tools.",
      "B": "Stop piping the diff via stdin and instead embed the diff contents inside the prompt string, so Claude Code treats the invocation as an\nagentic session rather than a stream-processing one.",
      "C": "Remove `--system-prompt` entirely and place the review instructions in a `CLAUDE.md` file at the repo root, since `--system-prompt` is\nincompatible with tool use under `-p`.",
      "D": "Keep `--system-prompt` and add `-allowedTools \"Read,Glob,Grep\"` so that the non-interactive `-p` mode permits file system tools that it\notherwise disables."
    },
    "correctAnswer": "A"
  },
  {
    "id": 118,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nYour pipeline reviews every PR using a single API call with a static prompt containing the diff and full text of each changed file – unchanged files\nare not included. Reviews are posted asynchronously and don't block PR creation. Developers report that reviews consistently miss bugs involving\ncross-file interactions – for example, a PR renames a function's parameters but the review doesn't flag callers in unchanged files that still use the\nold argument order. Evaluation shows cross-file bugs account for 35% of production incidents from reviewed PRs.\nWhat is the most effective change to your review design?",
    "options": {
      "A": "Redesign the review as a turn-limited agentic task where the model can read files and search the codebase via tools, following references\nto verify cross-file findings.",
      "B": "Run parallel review passes per changed file with direct dependents included in each pass, then aggregate and deduplicate findings using a\nfinal summarization call.",
      "C": "Add chain-of-thought instructions asking the model to list all external references in the diff, then reason step-by-step about how each\nchange might affect callers in other files.",
      "D": "Use static analysis to build a dependency graph of changed code, then expand the prompt to include all files within two dependency hops of\nany changed file."
    },
    "correctAnswer": "A"
  },
  {
    "id": 119,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code reviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and minimize false positives.\nA developer uses Claude Code to refactor a function during their development session. Before committing, they ask the same Claude session to review the code for issues. Later, a separate automated CI review catches several bugs that the same-session review missed.\nWhat best explains this discrepancy?\n",
    "options": {
      "A": "The CI review uses a more specific prompt tailored for catching bugs, while the developer's request was too general",
      "B": "The extended session length caused the context window to fill with conversation history, leaving less room for thorough analysis",
      "C": "The CI environment has access to the full codebase context while the local session only sees the current file",
      "D": "Claude retains context about its prior reasoning in the session, making it less likely to question its own decisions"
    },
    "correctAnswer": "D"
  },
  {
    "id": 120,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nYour pipeline includes a release notes generation step that classifies and summarizes approximately 200 commits at the end of each weekly\nrelease cycle. Each commit is currently sent as a separate Messages API call using a Sonnet-tier Claude model. The release notes aren't needed\nuntil the following morning (results have ~12 hours of acceptable latency). Your team needs to reduce per-token API cost for this step while\nkeeping the same model and prompts (no change to model tier or output quality).\nWhich approach satisfies all of these constraints?",
    "options": {
      "A": "Issue the 200 Messages API requests in parallel using concurrent connections, since concurrency lowers the per-token price charged by the\nAPI.",
      "B": "Concatenate all 200 commit messages into a single Messages API request and have the model return all summaries in one response, since\nfewer requests always reduces total token cost.",
      "C": "Submit the 200 requests to the Message Batches API with unique custom_ids and retrieve results once the batch ends, which applies a 50%\ndiscount to all input and output tokens.",
      "D": "Switch the summarization calls from the Sonnet-tier model to a Haiku-tier model to take advantage of Haiku's lower per-token rates."
    },
    "correctAnswer": "C"
  },
  {
    "id": 121,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nAfter deploying automated code review, developers report that approximately 35% of flagged findings are false positives falling into consistent\npatterns: style suggestions contradicting team conventions, security warnings for patterns safe in your deployment context, and performance\nsuggestions that would degrade your specific use case. You want to reduce false positives while maintaining the ability to catch genuine issues.\nWhich approach best enables the model to generalize its judgment to novel code patterns it hasn't seen before?",
    "options": {
      "A": "Create a comprehensive written specification of all patterns that should not be flagged, then include this full documentation in the system\nprompt.",
      "B": "Implement post-processing that uses keyword matching to filter out findings containing terms like \"convention,\" \"context-dependent,\" or\n\"trade-off.\"",
      "C": "Include few-shot examples in your prompt showing annotated code snippets that distinguish acceptable patterns from genuine issues in\neach category.",
      "D": "Add instructions to your system prompt to \"be conservative,\" \"only flag definite issues,\" and \"consider that some patterns may be\nintentional.\""
    },
    "correctAnswer": "C"
  },
  {
    "id": 122,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nYour automated review generates many findings per PR, but developer feedback shows roughly half are dismissed as \"not worth addressing.\"\nAnalysis reveals dismissed findings are often technically accurate but involve minor style preferences or patterns acceptable in your codebase.\nBefore adding infrastructure complexity, what prompt design change would most effectively reduce dismissals while maintaining detection of\ngenuine issues?",
    "options": {
      "A": "Add explicit criteria defining which issues to report (bugs, security) versus skip (minor style, local patterns)",
      "B": "Add instructions asking Claude to rate each finding's confidence (1-10) and only include findings rated 8 or higher",
      "C": "Append instructions to \"only report findings you are highly confident are genuine problems\"",
      "D": "Implement a secondary classification model that filters Claude's findings based on predicted developer acceptance"
    },
    "correctAnswer": "A"
  },
  {
    "id": 123,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nThe automated review consistently flags patterns your team uses intentionally – force-unwrapping optionals in test files, using large coordinator\nclasses that follow your established architecture, and importing internally-maintained modules marked as deprecated in the public SDK.\nDevelopers are dismissing roughly 30% of all findings as project-specific false positives.\nWhich approach prevents the model from generating these findings in the first place by supplying the project's conventions as persistent context\non every review?",
    "options": {
      "A": "Have developers add inline suppress-comments at flagged lines and preprocess diffs to exclude suppressed lines before sending code to\nthe model.",
      "B": "Build post-processing keyword filters that suppress findings containing terms like \"force unwrap,\" \"large class,\" or \"deprecated import\"\nbefore results reach developers.",
      "C": "Document the team's accepted patterns and intentional conventions in the project's CLAUDE.md file so the model receives this context\nduring every review.",
      "D": "Configure the review to analyze only the changed lines in the diff without surrounding file context, reducing the amount of code the model\nevaluates per review."
    },
    "correctAnswer": "C"
  },
  {
    "id": 124,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nYour test generation produces unit tests for new code, but reviews show 55% are low-value: trivial assertions that only verify functions don't throw\nexceptions, tests duplicating existing coverage, or tests ignoring your team's fixture conventions.\nHow do you reduce the rate of low-value tests being generated in the first place?",
    "options": {
      "A": "Document testing standards in CLAUDE.md including valuable test criteria, available fixtures with intended use cases, and examples\ndistinguishing meaningful behavioral tests from trivial assertions.",
      "B": "Restrict test generation to directories where historical quality metrics show higher acceptance rates, disabling it for areas where generated\ntests consistently require heavy editing.",
      "C": "Implement a two-phase generation where a second Claude call scores each test against quality criteria, filtering out low-scoring tests\nbefore presenting results to developers.",
      "D": "Add post-generation coverage analysis that automatically filters out any generated test that doesn't increase line coverage beyond what\nexisting tests provide."
    },
    "correctAnswer": "A"
  },
  {
    "id": 125,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nYour automated review CI jobs take 18 seconds to initialize before Claude begins analyzing code. Profiling reveals the delay comes from auto-\ndiscovery of hooks, MCP servers, plugins, skills, and multiple nested CLAUDE.md files throughout your monorepo. You need to cut startup time\nwhile ensuring reviews still enforce your team's coding standards, which are documented in your root-level CLAUDE.md file.\nWhat is the most effective approach?",
    "options": {
      "A": "Replace the default prompt entirely using --system-prompt-file ./CLAUDE.md, which bypasses default prompt assembly and loads only your\nproject rules.",
      "B": "Run with --bare mode and pass --append-system-prompt-file ./CLAUDE.md to explicitly load your project standards while skipping all auto-\ndiscovery.",
      "C": "Run with --bare mode and specify all review criteria directly in the -p prompt argument for each CI invocation, without referencing any\nexternal files.",
      "D": "Keep the default initialization and add --exclude-dynamic-system-prompt-sections to reduce per-machine prompt variability and improve\nprompt cache hit rates across runners."
    },
    "correctAnswer": "B"
  },
  {
    "id": 126,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nYour automated code review is missing genuine bugs in pull requests. Investigation reveals that your review prompt includes the instruction: \"Only\nflag critical issues that would definitely cause production failures. Ignore minor concerns and anything you're uncertain about.\" Developers\nconfirm that some missed bugs are real logic errors the model investigated but chose not to report. The team requires that review output remain\nstructured (each finding tagged with metadata) and actionable.\nWhich prompt change both removes the cause of the suppressed findings and preserves structured, tagged output for downstream filtering?",
    "options": {
      "A": "Add a second review pass that re-reads the diff using the same prompt, looking for anything the first pass may have missed.",
      "B": "Enable extended thinking and instruct the model to reason step-by-step about each code change before producing its review.",
      "C": "Remove all severity-related instructions from the prompt and let the model use its default judgment about what to report.",
      "D": "Instruct the model to report all findings with a confidence level and severity tag, deferring filtering to a downstream step."
    },
    "correctAnswer": "D"
  },
  {
    "id": 127,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nDuring initial testing of the automated review pipeline, you notice that reviews on large PRs (50+ changed files) sometimes take over 20 minutes\nand cost $8-12 per run due to extensive agentic loops – Claude reads files, runs analysis tools, and iterates many times. Your team needs each\ninvocation to abort once it reaches a fixed iteration count and a fixed dollar amount, enforced by Claude Code itself rather than the surrounding\njob runner.\nWhich configuration change directly enforces both of those per-invocation caps?",
    "options": {
      "A": "Set `--permission-mode dontAsk` to auto-deny any tool permission requests not in the explicitly allowed set.",
      "B": "Add `--max-turns 10 --max-budget-usd 2.00` to the `claude -p` invocation to cap iterations and spend.",
      "C": "Switch the `--model` flag to a smaller, cheaper model so each iteration uses fewer tokens and lower per-call cost.",
      "D": "Set `timeout-minutes: 5` on the GitHub Actions job step and monitor per-run costs via the Anthropic Console usage dashboard."
    },
    "correctAnswer": "B"
  },
  {
    "id": 128,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nIn addition to your CI pipeline, your organization has enabled Claude's managed Code Review (via the Claude GitHub App) on this repository, and\nreviews run automatically on each PR. Reviews average 18 findings per PR. Developer feedback reveals three categories of unwanted noise: (1)\nstyle and formatting issues already enforced by your linter in CI, (2) findings on auto-generated template code under `src/gen/`, and (3) rendering\nhelper patterns that are intentional project conventions but get flagged because they resemble common anti-patterns. Only about 4 findings per\nPR are genuine logic bugs.\nWhat is the most effective way to reduce this noise while preserving detection of real issues?",
    "options": {
      "A": "Create a REVIEW.md at the repository root with skip rules for CI-enforced checks and generated files, and a verification requirement that\nrendering-related findings must cite a specific line demonstrating incorrect behavior.",
      "B": "Add custom review instructions to a GitHub Actions workflow file, using the action's prompt parameter to suppress lint-duplicate findings,\nignore generated template code, and apply stricter evidence requirements for rendering-related issues.",
      "C": "Add detailed explanations to the project's CLAUDE.md describing which patterns are intentional, that linting is handled separately by CI, and\nthat the src/gen/ directory contains autogenerated template code.",
      "D": "Configure separate GitHub Action workflow files for each code area, one for generated code with findings suppressed, one for rendering\ncode with custom review instructions, and a general workflow for everything else."
    },
    "correctAnswer": "A"
  },
  {
    "id": 129,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nYour automated reviewer uses a single prompt covering security issues, API design, and business logic correctness. Your evaluation suite shows\nstrong recall for API design findings (82%) but poor recall for business logic edge cases in quiz scoring (34%). When you add few-shot examples\nof logic bugs to the prompt, logic recall improves to 41% but API design recall drops to 68%.\nHow should you address this trade-off to improve detection across both categories?",
    "options": {
      "A": "Provide the full repository as context instead of just the changed files and surrounding code, giving the model deeper visibility into\nbusiness logic patterns.",
      "B": "Split the review into separate focused prompts – one for security and API design, another for business logic – each with dedicated\nexamples, then consolidate findings before posting.",
      "C": "Upgrade to a more capable model tier, since its stronger reasoning will handle both concern types in a single prompt and eliminate the\nrecall tradeoff.",
      "D": "Replace the few-shot examples with a detailed checklist of specific logic edge cases to verify, such as division-by-zero in score calculations\nand boundary conditions in grading thresholds."
    },
    "correctAnswer": "B"
  },
  {
    "id": 130,
    "question": "You are integrating Claude Code into your Continuous Integration/Continuous Deployment (CI/CD) pipeline. The system runs automated code\nreviews, generates test cases, and provides feedback on pull requests. You need to design prompts that provide actionable feedback and\nminimize false positives.\nYour automated review calls the Claude API for each PR, using tool_use with a `report_findings` tool that returns a JSON array of finding objects\n(each with `file_path`, `line_number`, `severity`, `category`, and `description`). During testing on a large PR touching 30+ files, the response hits\nthe `max_tokens` limit and the output is truncated mid-JSON, causing your pipeline's parser to fail.\nWhat is the most effective way to handle this?",
    "options": {
      "A": "Split the review into multiple API calls that each analyze a subset of the changed files, then merge the resulting findings arrays.",
      "B": "Add retry logic that detects truncated JSON and re-sends the request with instructions to report only critical and high severity findings.",
      "C": "Switch from tool_use to prompting Claude to return findings as a markdown list.",
      "D": "Increase `max_tokens` to the model's maximum and instruct Claude to keep finding descriptions under 50 words each."
    },
    "correctAnswer": "A"
  },
  {
    "id": 131,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nEngineers frequently ask the agent to cross-reference code changes with Jira tickets during reviews – checking ticket descriptions, acceptance\ncriteria, and recent comments. This currently requires manually copy-pasting content into conversations. The team wants the agent to access this\nstandard Jira ticket data directly.\nWhat's the most effective approach?",
    "options": {
      "A": "Integrate an existing Jira MCP server that exposes tickets, comments, and metadata through discoverable tool interfaces.",
      "B": "Use the Bash tool with `curl` to call Jira's REST API, including authentication headers and parsing JSON responses inline.",
      "C": "Build a custom MCP server wrapping Jira's API with tools designed specifically for this team's code review workflow.",
      "D": "Export Jira tickets to markdown files in the repository that the agent accesses using the Read tool."
    },
    "correctAnswer": "A"
  },
  {
    "id": 132,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nAn engineer who just joined the team asks the agent to help them understand the authentication and authorization architecture before making\nsecurity improvements. The codebase has 800+ files across multiple services.\nWhat exploration strategy will most effectively build understanding, given Claude built-in tools and context limits?",
    "options": {
      "A": "Read all files containing \"auth\", \"login\", \"permission\", or \"token\" in their content or filename.",
      "B": "Use Grep to find authentication entry points, read those files, then follow imports and function calls to map the auth flow incrementally.",
      "C": "Launch parallel subagents to explore different services simultaneously, then synthesize their findings into an architectural overview.",
      "D": "Read any CLAUDE.md and README files first, then ask the engineer to specify which 10-15 files are most important for understanding the\nauth system."
    },
    "correctAnswer": "B"
  },
  {
    "id": 133,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nYour productivity agent connects to three MCP servers: an issue tracker (search_issues, get_issue, create_comment), a documentation wiki\n(search_docs, get_page, list_spaces), and a database explorer (run_query, get_schema, list_databases). When engineers ask cross-system\nquestions like \"What database tables are affected by the authentication refactor in PROJ-1234?\", monitoring shows the agent makes 8-10\nsequential tool calls, frequently issues exploratory calls because it lacks visibility into what content each server contains, and exhausts context\nspace before completing complex investigations.\nWhat architectural change best leverages MCP capabilities to address these issues?",
    "options": {
      "A": "Add an orchestrator that routes questions to a single server based on keywords",
      "B": "Expose each server's content catalog as MCP resources – issue summaries, documentation hierarchy, database schemas",
      "C": "Consolidate all three servers into a unified MCP server with cross-referencing capabilities",
      "D": "Add a prepare_investigation tool to each server that accepts a natural language question and returns relevant content summaries"
    },
    "correctAnswer": "B"
  },
  {
    "id": 134,
    "question": "You are building developer productivity tools using the Claude Agent SDK. The agent helps engineers explore unfamiliar codebases, understand\nlegacy systems, generate boilerplate code, and automate repetitive tasks. It uses the built-in tools (Read, Write, Bash, Grep, Glob) and integrates\nwith Model Context Protocol (MCP) servers.\nYou're building a security scanning workflow.\nWhen engineers need to locate all occurrences of a dangerous function like eval() across a large codebase, which tool should your agent use for\ncontent search?",
    "options": {
      "A": "Use Glob with a pattern like `**/*eval*` to find files, then Read each matching file.",
      "B": "Use Bash to run `Is -R | grep eval` to recursively list files containing eval.",
      "C": "Read the project's main entry file and follow import statements to trace where eval might be used.",
      "D": "Use Grep to search for the pattern \"eval(\" across all files in the codebase."
    },
    "correctAnswer": "D"
  }
];
