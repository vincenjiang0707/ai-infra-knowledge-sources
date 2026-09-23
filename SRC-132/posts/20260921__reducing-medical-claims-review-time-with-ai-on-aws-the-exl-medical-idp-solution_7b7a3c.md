# Reducing medical claims review time with AI on AWS: The EXL Medical IDP solution

source: https://aws.amazon.com/blogs/machine-learning/reducing-medical-claims-review-time-with-ai-on-aws-the-exl-medical-idp-solution/
published: Mon, 21 Sep 2026 16:24:40 +0000

[Artificial Intelligence](https://aws.amazon.com/blogs/machine-learning/)

# Reducing medical claims review time with AI on AWS: The EXL Medical IDP solution

Insurance claims adjusters spend over 100 minutes per case manually reviewing medical records. The EXL AI-powered Medical intelligent document processing (IDP) solution, built on AWS, transforms this process. It combines IDP with domain-specific large language models (LLMs) to extract, summarize, and query medical information at enterprise scale.

## Challenge: Medical records are complex, voluminous, and critical

In insurance claims adjudication and life underwriting, medical records are the foundation of every decision. Claim adjusters and underwriters must review these records, often several hundred pages long, to assess validity, determine payouts, or make underwriting decisions.

The challenge isn’t simply volume. Medical records are unstructured, filled with specialized clinical terminology, and require the reviewer to connect disparate data points about a patient’s condition and its evolution over time. The documents themselves span dozens of types: chiropractic care notes, diagnostic tests, emergency room visits, operative reports, physician consultations, prescription drug reports, psychiatric evaluations, lab results, independent medical examination (IME) reports, and peer reviews, among others.

This review demands deep medical domain expertise, sustained concentration, and interpretive judgment. Given this complexity, the process is slow, manual, and prone to inconsistencies. Different professionals interpret the same medical data in different ways. The consequences are real: delayed claim settlements, accuracy issues in evaluations, increased indemnity costs, adverse customer experience, and heightened regulatory scrutiny.

## About EXL

[EXL](https://www.exlservice.com/) is a data analytics, AI, and digital solutions provider serving Fortune 500 organizations for over 25 years. With over 50,000 professionals globally, EXL brings deep expertise in insurance, healthcare, banking, capital markets, retail, media and communications, and energy to reimagine business models, deliver measurable outcomes, and accelerate innovation.

## Solution: Two AI applications, one intelligent pipeline

EXL addressed this challenge by combining two complementary AI applications into a single end-to-end solution, hosted on AWS:

**Xtrakto.AI**handles document ingestion, splitting, classification, extraction, enrichment, and postprocessing. It is a template-agnostic IDP application that uses computer vision, natural language processing (NLP), and agentic AI workflows to extract structured data from various document types without requiring pre-configured templates.**EXL Insurance LLM**provides the domain intelligence layer: medical summarization, natural-language querying, deep reasoning with traceability, and structured output generation. Fine-tuned on insurance and medical domain data, it understands clinical terminology, ICD (International Classification of Diseases) and CPT (Current Procedural Terminology) codes, diagnosis-treatment relationships, and the specific needs of claims and underwriting workflows.

Together, these applications form an automated, scalable pipeline that transforms raw medical documents into actionable intelligence for claims adjusters, underwriters, and care coordinators.

EXL built the solution on AWS to keep model development and production inference under one roof with consistent security controls. [Amazon SageMaker AI](https://aws.amazon.com/sagemaker/ai/) provides the managed training and inference environment for the domain-specific EXL Insurance LLM: multi-GPU fine-tuning, isolated experimentation separated from production, and real-time inference endpoints that scale with claim volume. [Amazon Bedrock](https://aws.amazon.com/bedrock/) complements this with on-demand access to general-purpose foundation models through a single API. With this access, EXL can apply the right model to each task: the fine-tuned Insurance LLM for domain reasoning and general-purpose models for broader language tasks, without managing additional infrastructure. Both services operate within access controls scoped by AWS Identity and Access Management (IAM), which is essential for a workflow handling protected health information.

## Architecture overview

The solution runs entirely within an AWS Region, with upstream and downstream client applications connecting through secure APIs. The architecture follows an 11-step flow, from ingestion through output delivery, with a separate model development environment for continuous improvement.

The pipeline is built on the following AWS services:

[Amazon API Gateway](https://aws.amazon.com/api-gateway/)for secure ingestion and results delivery APIs (steps 1 and 11).[Amazon Cognito](https://aws.amazon.com/cognito/)for request authentication and authorization (step 2).[AWS Step Functions](https://aws.amazon.com/step-functions/)as the orchestration engine that coordinates sub-requests, routing, and extraction workflows (step 3).[Amazon Textract](https://aws.amazon.com/textract/)and[AWS Lambda](https://aws.amazon.com/lambda/)for document preprocessing: machine readability checks, OCR, file type conversion, and text embedding generation (step 4).[Amazon SageMaker AI](https://aws.amazon.com/sagemaker/ai/)for machine learning (ML) model inference and data retrieval based on trained domain models (step 5).[Amazon DynamoDB](https://aws.amazon.com/dynamodb/)and[Amazon Relational Database Service (Amazon RDS)](https://aws.amazon.com/rds/)for data enrichment using internal and external reference databases (step 6).- Amazon SageMaker AI real-time inference endpoints serve the EXL Insurance LLM for validation, summarization, querying, and agentic reasoning (step 7).
[Amazon Bedrock](https://aws.amazon.com/bedrock/)provides on-demand access to general-purpose foundation models that complement the domain-specific EXL Insurance LLM for general reasoning tasks. For model availability by AWS Region, refer to[Supported models by AWS Region in Amazon Bedrock](https://docs.aws.amazon.com/bedrock/latest/userguide/models-regions.html).- AWS Lambda for output generation in multiple formats (step 8).
[Amazon CloudWatch](https://aws.amazon.com/cloudwatch/)for application and model monitoring dashboards (step 9).[Amazon Simple Storage Service (Amazon S3)](https://aws.amazon.com/s3/)as the central data lake for document storage and processed outputs (step 10).- Amazon SageMaker AI (in an isolated model development environment) for
[model training, fine-tuning](https://docs.aws.amazon.com/sagemaker/latest/dg/jumpstart-fine-tune.html), and experimentation (step 0).

## Building the EXL Insurance LLM on Amazon SageMaker AI

A critical differentiator of this solution is the EXL Insurance LLM: a domain-specific large language model fine-tuned specifically for insurance claims workflows involving medical records. Rather than relying on general-purpose LLMs that lack specialized insurance and medical domain knowledge, EXL built a purpose-trained model on Amazon SageMaker AI, benchmarked against general-purpose models on insurance-specific NLP tasks.

### Why fine-tune rather than prompt?

General-purpose models like GPT-4 or Claude possess broad language understanding but lack the specialized vocabulary, reasoning patterns, and workflow awareness needed for insurance claims adjudication. Insurance claims involve multiple distinct tag types for medical record annotation, domain-specific summarization formats (economic and non-economic damages), and negotiation guidance generation. These tasks require deep domain adaptation that prompting alone cannot achieve consistently at scale.

### Training data and preparation

EXL curated training data from nine years of insurance claims operations, comprising over 13,500 records spanning both structured database records and unstructured medical documents. The data preparation pipeline on AWS included:

**Optical character recognition (OCR) with Amazon Textract:**Extracting text from scanned medical PDFs while preserving positional context at the line and word level, critical for maintaining the relationships between medical findings.**Junk page detection:**An automated classifier to identify and remove irrelevant or poorly scanned pages that would degrade training quality.**Data de-identification:**De-identification procedures that align with HIPAA requirements to remove protected health information before training, so the model does not learn sensitive patient data.**Multi-tag consolidation:**Grouping multiple tag citations per page into unified training examples, helping prevent the model from producing inconsistent outputs when a single page contains multiple medical findings.

### Fine-tuning approach on SageMaker AI

EXL used [Parameter-Efficient Fine-Tuning](https://huggingface.co/docs/peft/en/index) (PEFT) with [Low-Rank Adaptation](https://arxiv.org/abs/2106.09685) (LoRA) on Amazon SageMaker AI. This approach adapts the model efficiently without modifying all parameters of the base model, reducing compute costs while maintaining performance. The training used:

- Multi-GPU configurations on SageMaker AI training instances with NVIDIA GPUs.
- Advanced parallelism (data and model parallelism) to optimize training throughput at scale.
- NVIDIA
[NeMo](https://developer.nvidia.com/nemo-framework)framework for building and managing the training pipeline. - Isolated SageMaker AI environment (step 0 in the architecture) separated from production inference, so model experimentation does not impact live workloads.

### Performance results

In internal benchmarking by EXL, the fine-tuned EXL Insurance LLM showed strong performance across key claim-workflow tasks (tagging, summarization, question-answering, and reasoning), assessed using automated metrics (BLEU, ROUGE, BERTScore, METEOR) and blind review by three insurance subject-matter experts.

For methodology and detailed results, see [EXL white paper on the Insurance LLM](https://www.exlservice.com/insights/white-paper/ai-powered-insurance-workflows-operationalizing-llms-with-exl-insurance-llm).

With this pipeline, EXL reduced medical record review time from days to hours, with human-in-the-loop validation at critical stages helping maintain quality while reducing turnaround time.

## How it works: From document to decision

The pipeline moves each document through seven stages, from ingestion to structured output delivery. The following sections walk through each stage.

### Stage 1: Document splitting and classification

The pipeline begins when upstream applications submit extraction requests through the Ingestion API, built on Amazon API Gateway. Documents arrive through multiple channels and in multiple formats. AWS Lambda functions handle initial file processing using Apache Tika for parsing and post-OCR normalization, storing raw documents in Amazon S3.

After authentication through Amazon Cognito, the orchestration engine (AWS Step Functions) takes over, creating sub-requests based on the input and routing content to appropriate processing modules.

Xtrakto.AI’s classification engine is template agnostic and inference based. Rather than relying on document layout or predefined templates, it uses few-shot and transfer learning methods to classify content based on meaning and context. As a result, the system can classify new document types with limited training samples. Bundled files (email messages with multiple attachments) are split into individual sub-documents, each routed to the appropriate downstream extraction module.

### Stage 2: Data extraction with confidence scoring and traceability

This is the core of the pipeline, where Xtrakto.AI’s extraction capabilities come together across preprocessing, computer vision, and domain-specific extraction.

#### Preprocessing

Documents undergo machine readability checks, OCR with Amazon Textract, file type conversion, and text embedding generation. These steps run as Lambda functions coordinated by Step Functions. Computer vision models (CNNs, RCNNs) deployed on Amazon SageMaker AI process the pixel-level image data to address quality issues common in scanned medical records: low resolution, noise from wrinkles or stains, skewness, and mixed handwritten and printed content. These models identify duplicate pages, detect bounded and unbounded tables, identify extraction zones, detect signatures, and interpret barcodes and QR codes.

Approximately 25–30 percent of documents contain handwritten content, ranging from structured form fills (low complexity, approximately 50–60 percent of handwritten volume) to semi-structured annotations (approximately 15–20 percent) to fully free-form physician notes (approximately 15–20 percent). Each type requires specialized processing.

#### Context-based extraction

Xtrakto.AI doesn’t configure input templates to look for information at specific locations. Extraction is context based:

- For structured and semi-structured documents, computer vision (CV) models identify zones and extract key-value pairs. A built-in domain ontology combined with semantic similarity NLP models maps extracted keys to business-specific fields.
- For highly unstructured content (physician notes, operative reports), extraction is orchestrated through a LangGraph-based agentic workflow. This decomposes extraction into structured reasoning steps, using machine comprehension and question-answering models for targeted field-level extraction, while transformer models provide contextual understanding for ambiguous cases.

Amazon SageMaker AI hosts the family of inference models used for extraction. Traditional approaches (SVM, gradient boosting) handle structured classification tasks, and transformer architectures (BERT, GPT, BART variants) enriched with domain-specific medical and insurance data handle contextual extraction.

#### Confidence scoring and human-in-the-loop

Every extracted field receives a confidence score of 0-100. Fields below a configurable threshold are routed to human validators through the EXL Xtrakto.AI validation screen for verification. This feedback continuously improves model accuracy over time.

### Stage 3: Data enrichment and integration

Extracted data is augmented using internal and external reference databases stored in Amazon DynamoDB and Amazon RDS. This enrichment step validates extracted codes against ICD-10, CPT, and Healthcare Common Procedure Coding System (HCPCS) libraries, normalizes dates and terminology, and resolves cross-field consistency issues. Enriched data is stored back in the Amazon S3 data lake for downstream consumption.

### Stage 4: Intelligent summarization

This is where the EXL Insurance LLM takes over, served from inference endpoints on Amazon SageMaker AI. Complex medical records spanning hundreds of pages are condensed into structured summaries tailored to the user’s needs.

The summarization engine offers flexibility: users choose between short, medium, or long summaries depending on their workflow. The Insurance LLM extracts, labels, summarizes, and presents the most relevant clinical information while preserving the original context and narrative flow of the document.

Through a feedback mechanism, users can rate and correct summaries. These corrections feed into model fine-tuning on Amazon SageMaker AI, continuously improving summarization quality.

### Stage 5: Natural-language querying

Beyond summaries, users need to ask specific questions about a medical record and get precise, sourced answers. The querying capability, powered by the Insurance LLM on Amazon SageMaker AI, supports three modes:

**Pre-defined FAQs**for common questions across claim types.**Bundled questions**that group related queries and fire them together for batch processing.**Open queries**in everyday language, letting users retrieve specific information without complex search syntax.

The Insurance LLM understands the intent behind each query and provides accurate answers grounded in the underlying document data. It handles multiple queries simultaneously, making it practical for high-volume operational use.

### Stage 6: Deep reasoning with traceability

For complex cases requiring clinical judgment support, the solution provides deep reasoning capabilities with full traceability:

**Source-level traceability:**Every Q&A response and summary links back to the exact source data or document segment, so reviewers can verify AI-generated insights against original records.**Overwrite and feedback:**Users can correct inaccuracies by editing generated summaries or answers and rate the quality of outputs. These corrections feed into continuous model improvement, creating a virtuous cycle where the system becomes more accurate with use.

This traceability is essential in regulated environments where decisions must be auditable and defensible.


#### Responsible AI and production safeguards

Because this workflow handles protected health information and produces AI-generated clinical and claims insights, responsible-AI controls are built into the deployment rather than added on. Generative outputs pass through content-filtering and grounding checks before they reach a reviewer, so summaries and answers stay anchored to the source record and within policy. Source-level traceability makes every output auditable back to the originating document, human-in-the-loop validation gates low-confidence results, and de-identification procedures that align with HIPAA requirements protect patient data throughout the pipeline. Together these controls help the solution ship safely in a regulated healthcare context.

### Stage 7: Structured output and visualization

The final stage generates output through AWS Lambda functions and delivers results through the Results API (Amazon API Gateway). Downstream applications retrieve processed data in the format they need:

**Exportable PDF reports:**Unified, AI-powered reports combining extraction results, summaries, and Q&A outputs.**Organized document indexing:**Structured, scroll-free navigation for instant access to key sections within large medical records.**Chronological charts with hyperlinking:**Visual diagnosis history organized by year, with links for detailed clinical insights.**Multiple export formats:**JSON, XML, CSV, flat files, with configurable output schemas to match downstream system requirements.- Output data is stored in the Amazon S3 data lake, and Amazon CloudWatch provides end-to-end monitoring dashboards covering model performance, extraction accuracy, processing throughput, and system health.

## Real-world impact: Clinical case management at scale

A large healthcare payer faced significant operational challenges in clinical case management. Like the claims adjusters described earlier, the payer’s nurses and care coordinators were also spending over 100 minutes per case, here on manual data retrieval, validation, and preparation of clinical summaries. Information was fragmented across multiple systems: electronic health records, care management systems, claims systems, and scanned medical documentation.

The organization implemented the EXL Medical IDP solution to replace these fragmented manual workflows with a unified, intelligent pipeline.

**What was deployed:**

- Single API-led orchestration (through Amazon API Gateway and AWS Step Functions) across multiple clinical systems (EPIC, CarePort, Predictal, document management systems).
- Intelligent extraction agents processing data in multiple formats (JSON and Fast Healthcare Interoperability Resources (FHIR) bundles, scanned PDFs) from disparate clinical sources.
- LLM-driven extraction and classification of medications, past medical history, diagnoses, procedures, labs, and care notes using the Insurance LLM on Amazon SageMaker AI.
- Automated validation using industry-standard medical codes, resolving data conflicts across sources while maintaining traceability.
- Automated clinical summary generation with human-in-the-loop validation.

**Results:**

**Reduced manual effort:**Automated data ingestion, extraction, validation, and summarization reduced time spent per case, freeing nursing teams to focus on patient care.**Alleviated operational bottlenecks:**Standardized, AI-generated clinical summaries removed delays caused by manual navigation across multiple systems.**Accelerated member outreach:**Faster availability of complete, validated case summaries supported quicker outreach and more proactive care management.**Increased clinical bandwidth without additional headcount:**Productivity gains translated directly into higher case-handling capacity for nurses and care coordinators.**Improved accuracy and compliance:**Validation against industry-standard codes, source-level traceability, and human-in-the-loop review helped maintain data integrity in regulated healthcare environments.

## Conclusion

Medical records sit at the center of critical insurance and healthcare decisions, yet the process of extracting intelligence from them has remained largely manual for decades. The EXL Medical IDP solution demonstrates that this no longer needs to be the case.

By combining Xtrakto.AI’s template-agnostic document processing with the domain intelligence of the EXL Insurance LLM, EXL created a solution that handles the full lifecycle, from raw document ingestion through intelligent extraction, summarization, querying, and structured output delivery. The pipeline runs on AWS services including Amazon API Gateway, Amazon Cognito, AWS Step Functions, [Amazon Textract](https://aws.amazon.com/textract/), [Amazon SageMaker AI](https://aws.amazon.com/sagemaker/ai/), [Amazon Bedrock](https://aws.amazon.com/bedrock/), Amazon S3, Amazon CloudWatch, and Amazon DynamoDB.

The key principle underlying this solution is augmentation, not replacement. Human expertise remains central through confidence-based routing, human-in-the-loop validation, and continuous feedback loops. AI handles the volume and the repetitive pattern recognition. Humans handle the judgment and the exceptions.

Learn more about [healthcare](https://www.exlservice.com/industries/health-and-life-sciences) and [insurance solutions](https://www.exlservice.com/industries/insurance) from EXL and explore AWS solutions for [healthcare](https://aws.amazon.com/health/) and [insurance](https://aws.amazon.com/solutions/financial-services/insurance/). To go deeper, see the [Amazon Bedrock documentation](https://docs.aws.amazon.com/bedrock/) and [Amazon SageMaker AI fine-tuning documentation](https://docs.aws.amazon.com/sagemaker/latest/dg/jumpstart-fine-tune.html). You can also explore various [AWS samples](https://github.com/aws-samples/) on GitHub.

For a related customer story, read [AI-Powered Collections: How EXL Uses AI on AWS for Debt Recovery at Scale](https://aws.amazon.com/blogs/industries/ai-powered-collections-how-exl-uses-ai-on-aws-for-debt-recovery-at-scale/).