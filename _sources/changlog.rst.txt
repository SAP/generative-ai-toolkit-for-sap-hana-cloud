Changelog
=========

**Version 1.1.260714**

``New Functions``
    - Added the ``hana_ai.retrieval`` package to host the HANA AI Core retrieval clients used by the MCP tools; the package exposes ``ObjectDiscovery``, ``DataRetrieval``, and the shared ``RetrievalBase`` used by both. The previous internal ``hana_ai.agents.hana_agent`` package has been removed in favor of ``hana_ai.retrieval``.
    - Renamed the MCP-exposed retrieval tools to ``object_discovery`` (schema/object metadata retrieval) and ``data_retrieval`` (data retrieval over remote-source-backed procedures), replacing the previous ``discovery_agent``/``data_agent`` names. The corresponding tool classes are ``ObjectDiscoveryTool`` and ``DataRetrievalTool`` in ``hana_ai.tools.hana_ml_tools.graph_tools``.
    - Added ADI / CV^2 based intermittent-demand classification in ``TimeSeriesCheck`` (``ts_check`` MCP tool). The check now reports ADI and CV^2 alongside the previous statistics and labels each series as ``smooth``, ``erratic``, ``intermittent``, or ``lumpy`` using the standard thresholds (ADI >= 1.32, CV^2 >= 0.49). ContextAgent skills routing was updated accordingly to prefer ``intermittent_forecast`` with ``method=constant`` for intermittent series and ``method=sporadic`` for lumpy series.
    - Added HTTP MCP audit-context plumbing in ``hana_ai.tools.toolkit``: the toolkit now attaches a ``MCPAuditMiddleware`` for HTTP transport (via ``fastmcp.server.middleware``) and mirrors the same context capture on the stdio path so both transports emit consistently keyed audit events. Introduced ``DEFAULT_MCP_SESSION_CONTEXT_KEYS`` in ``hana_ai.tools.hana_ml_tools.utility`` as the canonical set of MCP audit fields (client-declared identity, HANA-authenticated identity, tool name, target tables, response size, model storage name/version, timing, and correlation identifiers).
    - Added ``ensure_mcp_audit_log`` and ``find_free_port`` helpers in ``hana_ai.tools.hana_ml_tools.utility`` to make bootstrapping a local MCP audit-log file and picking a free HTTP port reusable from example scripts.
    - Added ``extra_headers`` on the MCP HTTP client in ``hana_ai.client.mcp_client``. Callers can now pass arbitrary key/value pairs (for example, a routing hint or a trace-id header) that are merged into the outgoing ``httpx`` client and per-request headers on top of the standard MCP protocol and session headers.

**Version 1.1.260701**

``Bug Fixes``
    - Fixed ContextAgent failure with newer Anthropic Claude deployments (e.g. ``anthropic--claude-4.6-sonnet``) on SAP Generative AI Hub that reject ``temperature`` and ``top_p`` being set together; the agent now sanitizes the LLM sampling parameters on construction and drops ``top_p`` when ``temperature`` is also set.
    - Fixed ContextAgent hallucinating table, model, and version identifiers (e.g. substituting ``SALES_REFUNDS_TEST`` for the previously recorded ``SALES_REFUNEDS_PREDICT``) by feeding ``DECISIONS.md`` and ``TODO.md`` back into the per-turn ``memory_notes`` block alongside ``NOTES.md`` and hardening the system prompt to forbid inventing identifiers not present in context.
    - Fixed ``invalid table name: Could not find table/view PREDICT_RESULT_...`` errors from ``AutomaticTimeSeriesLoadModelAndPredict``, ``AdditiveModelForecastLoadModelAndPredict``, and ``MassiveAutomaticTimeSeriesLoadModelAndPredict`` when the model storage name (or predict input table/schema) contained lower-case characters: user-supplied identifier fragments are now uppercased before being embedded in the ``PREDICT_RESULT_``/``REASON_CODE_``/``PREDICT_ERROR_`` table names so the created table aligns with HANA's default folding on unquoted references.
    - Fixed ContextAgent hanging notebook cells for many minutes when a tool call got stuck on the HANA/PAL backend (previously ``max_iterations`` bounded the number of tool calls but not the wall-clock time, so eight stuck iterations could exceed ten minutes). Added ``AgentConfig.max_turn_seconds`` (default 300s, set to ``None``/``0`` to disable) which runs the executor on a daemon thread with a join timeout; when the deadline fires the current turn short-circuits with an actionable message instead of hanging.

**Version 1.1.260410**

``Bug Fixes``
    - Fixed the line plot tool issue when the column names in the predicted results table are different from the default column names expected by the tool.

**Version 1.1.260408**

``New Functions``
    - Added a standalone ContextAgent skills catalog at hana_ai.iagents.skills.md to make skill definitions easier to review, extend, and maintain.
    - Added markdown-based skill loading in ContextAgent with built-in fallback support for existing deployments.
    - Added dedicated dataset preparation tools for CSV import and time-ordered train, test, validation table generation in conversational forecasting workflows, including split_table_for_forecasting.
    - Added grouped additive forecasting tools backed by AdditiveModelForecast(massive=True) for save-and-predict workflows across many related series.

``Enhancements``
    - Added aggregate and file-level ContextAgent memory reset commands for clearing persisted notes, TODOs, decisions, context, chat history, and session summaries without deleting the storage directory.
    - Expanded ContextAgent skill coverage for dataset preparation, time-series profiling, prediction-result analysis, grouped forecasting, artifact generation, and dataframe-oriented fallback workflows.
    - Improved fallback skill selection so profiling, post-prediction analysis, grouped forecasting, artifact generation, and SQL comparison requests map more reliably to the intended skills.
    - Added validation for markdown-defined skills so malformed entries are ignored unless they provide a valid Goal section.
    - Clarified that dataset splitting currently targets forecasting scenarios and preserves chronology through time-ordered splitting.
    - Improved forecasting prediction robustness so automatic, additive, and grouped prediction tools proactively validate and repair predict inputs to inference-only columns when users accidentally pass labeled holdout tables.
    - Improved ContextAgent tool-failure handling with more actionable diagnostics for predict-versus-score input mismatches and backend PAL runtime failures during forecasting workflows.

``API Changes``
    - ContextAgent now prefers loading skills from the colocated markdown catalog and merges them with the built-in fallback skills.
    - ContextAgent is the recommended target for future live end-to-end scenario expansion; HANAMLRAGAgent and Mem0HANARAGAgent are no longer recommended for new scenario coverage.

**Version 1.0.260331**

``New Functions``
    - Added prediction result analysis skills and dataframe manipulation skills in the context agent to provide better insights and analysis of the predicted results.

**Version 1.0.260330**

``New Functions``
    - Added context agent with markdown type memory to support better context management and display in the conversation.

**Version 1.0.260319**

``Bug Fixes``
    - Fixed the hullucination issue of forecast tools in Mem0HANARAGAgent when the input table name is very similar to the prediction result.

**Version 1.0.260316**

``API Changes``
    - Removed the graph_tools due to the stored procedure missing.

**Version 1.0.260212**

``Bug Fixes``
    - Fixed the version incomatibility issue of langchain and sap-ai-sdk-gen.

**Version 1.0.260116**

``Enhancements``
    - Added reset_tools method to HANAMLToolkit to reset the toolkit's tools.

**Version 1.0.251223**

``Bug Fixes``
    - Fixed the import issues in hana_ai agents and tools.
    - Fixed the missing parameter in PALEmbeddings.

**Version 1.0.251217**

``Enhancements``
    - Added the customized procedure name in CAP generation tool.

**Version 1.0.251001**

``Bug Fixes``
    - Fixed the output parser issue in SmartDataFrame's transform function.

**Version 1.0.250930**

``Enhancements``
    - Added MassiveAutomaticTimeSeriesFitAndSave, MassiveAutomaticTimeSeriesLoadModelAndPredict, and MassiveAutomaticTimeSeriesLoadModelAndScore tools to support massive time series model training, prediction, and scoring with group_key parameter.
    - Added MassiveTSOutlierDetection tool to support massive time series outlier detection with group_key parameter.
    - Added TSMakeFutureTableForMassiveForecastTool to create future tables for massive time series forecasting with group_key parameter.
    - Added MassiveTimeSeriesCheck tool to perform time series analysis and generate reports for multiple time series with group_key parameter.
    - Updated HANAMLToolkit to include the new massive time series tools.

``API Changes``
    - Modified SelectStatementToTableTool to include a 'force' parameter that allows overwriting existing tables.
    - Changed "Timeseries" to "TimeSeries" in class names for consistency.

``Bug Fixes``
    - Fixed an issue for text with special characters in the HANAVectorEmbeddings class.

**Version 1.0.250923**

``Enhancements``
    - Enhanced the outputs of tools when select_statement is too large by creating temporary tables with unique names.
    - Added additive_model_forecast_tools and intermittent_forecast df tools to the default tools in SmartDataFrame.

**Version 1.0.250918**

``Enhancements``
    - Added HANA table schema support for tools.
    - Improved output information for outlier detections.
    - Removed the hana_connection_context parameter from the `HANAMLRAGAgent` class and infer it from the tools.
    - Refine the default value of `max_iterations` parameter of `HANAMLRAGAgent` class parameters from 10 to 20.
    - Change the default value of `vector_store_type` parameter of `HANAMLRAGAgent` class from "faiss" to "hanadb".
    - Change the default value of `long_term_db` parameter of `HANAMLRAGAgent` class from sqlite to HANA DB.
    - Added the `embedding_service` parameter to the `HANAMLRAGAgent` class to allow users to pass their own embedding service. The default embedding service has been changed from `GenAIHubEmbeddings` to `HANAVectorEmbeddings`.
    - Added `PAL CrossEncoder` as the default cross-encoder model for reranking in the `HANAMLRAGAgent` class. If it is not available, it will fall back to `sentence-transformers/all-MiniLM-L6-v2`.
    - Added `session_id` parameter to the `HANAMLRAGAgent` class to support multiple sessions in long-term memory. By default, it is set to "global_session".
    - Removed the restriction to save memory into long term memory when the result is pandas data or large data. Now, all the results will be saved into long term memory with chunking and embeddings.
    - Deprecated the code template tool and python REPL tool in `SmartDataFrame` class. Users can use the tools from `df_tools` as default tools instead.

**Version 1.0.250909**

``New Functions``
    - Added `TSMakeFutureTableTool` to create a future table for time series forecasting.
    - Added `SelectStatementToTableTool` to execute a SELECT SQL statement and store the result in a new table.

**Version 1.0.250904**

``Bug Fixes``
    - Fixed the issue of calling code template tool.

**Version 1.0.250707**

``Enhancements``
    - Added `vector_store_type` parameter to `HANAMLRAGAgent` class to support different vector store types, including "hanadb" and "faiss".
    - Improved the `HANAMLRAGAgent` class to handle vector store initialization and updates more efficiently.

``Bug Fixes``
    - Fixed the parameter issues in `HANAMLRAGAgent` class by adding rerank_candidates and rerank_k parameters.

**Version 1.0.250702**

``New Functions``
    - Added `HANAMLRagAgent` class to enable Retrieval-Augmented Generation (RAG) capabilities, leveraging a hybrid short-term and long-term memory architecture with CrossEncoder reranking techniques.

**Version 1.0.250630**

``New Functions``
    - Added hdi artifacts tool.

**Version 1.0.250617**

``New Functions``
    - Added model deletion tool and chat history deletion tool to hanaml Agent.

**Version 1.0.250530**

``Enhancements``
    - Added unsupported tools check (classfication, regression).
    - BAS integration enhancements.

**Version 1.0.250520**

``Enhancements``
    - Added set_return_direct function in hanaml Agent.

``Bug Fixes``
    - Fixed the prompt in hanaml Agent to enable tool cal.
    - Fixed CAP generation temporary location in MacOS.

**Version 1.0.250509**

``Enhancements``
    - Output the inspect code for BAS integration.

**Version 1.0.250506**

``Enhancements``
    - Enhanced the seasonality detection for additive_model_forecast_tools.
    - Provide table meta information and supported algorithms in ts_check tool.

**Version 1.0.250424**

``Enhancements``
    - Added input table check and columns check to avoid stopping the reasoning.
    - Added samples to ts_check tool.

``Bug Fixes``
    - Fixed wrong report filename issue. (hana-ml appends _report.html to the file.)

**Version 1.0.250411**

``Enhancements``
    - Save observations to chat history in HANA ML agent. Added max_observations parameter to control the number of observations saved in the chat history.
    - Adjust the default value of fetch_data tool to return pandas indirectly to avoid chain stopping due to the tool call of fetch_data in the intermediate step.

**Version 1.0.250410**

``Enhancements``
    - Enhanced the HANA SQL agent to support case-sensitive SQL queries.
    - Added create_hana_sql_toolkit function to create a toolkit for HANA SQL.
    - Optimized the chat history management in HANA ML agent.

``Bug Fixes``
    - Fixed the accuracy_measure tool issue when evaluation_metric="spec".

**Version 1.0.250407**

``Enhancements``
    - Improved `forecast_line_plot` tool to automatically detect the confidence if it is not provided.
    - Serialized the tool's return if it is pandas DataFrame when `return_direct` is set to `False`.

``Bug Fixes``
    - Fixed the json serialization issue when the tool's return contains Timestamp.

**Version 1.0.250403**

``New Functions``
    - Added `list_models` tool to list all trained models in the model storage.
    - Added `accuracy_measure` tool to measure the accuracy of a model on a test dataset for time series forecasting.

``Enhancements``
    - Improved the `intermittent_forecast` tool to use CrostonTSB instead.
    - Added parameter `return_direct` to all tools and toolkit.
    - Improved the `fetch_data` tool to return a pandas DataFrame instead of a list of dictionaries. By default, the tool parameter `return_direct` is set to `True`, which means the tool will return a pandas DataFrame.
