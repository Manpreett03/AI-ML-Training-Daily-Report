**Project Title:** AI Skin Specialist – Voice & Vision Consultation Assistant  
**Domain:** Artificial Intelligence & Machine Learning (Multimodal AI & Speech Systems)  
**Student Name:** [Manpreet Kaur]  
**Roll No:** [URN : 2435083]  
**Department:** Computer Science & Engineering  
---
## 📌 Training Overview & Objectives
This repository documents the daily learning logs, practical experiments, and developmental milestones achieved during the 30-day industrial/institutional training in Artificial Intelligence and Machine Learning. 
The training followed a structured, project-oriented curriculum centered around the development of the **AI Skin Specialist**, an end-to-end multimodal consultation application. The system integrates Automatic Speech Recognition (ASR), Multimodal Vision-Language Models (VLM), Neural Text-to-Speech (TTS), and Computer Vision frame extraction within a responsive web interface.
---
## 🛠️ Technology Stack & Libraries
- **Language:** Python 3.13
- **Speech-to-Text:** OpenAI Whisper (`whisper-large-v3`) via Groq Cloud API
- **Vision-Language Model:** Qwen Vision (`qwen/qwen3.6-27b` / `qwen3.8-27b`) via Groq Cloud API
- **Text-to-Speech:** Deepgram Aura (`aura-asteria-en`) & gTTS (Fallback)
- **Computer Vision:** OpenCV (`cv2`) & Pillow (`PIL`)
- **Web Interface:** Gradio Blocks API
- **Environment & Dependency Management:** `uv`, `python-dotenv`, `pyproject.toml`
---
# 🗓️ Daily Training Logs (Day 1 – Day 30)
---
### Day 01: Training Orientation & Problem Formulation
- **Domain:** Problem Identification in Healthcare AI
- **Concepts Covered:** Understanding the role of Generative AI and Multimodal systems in modern healthcare. Identified challenges in first-line dermatological screening, such as long clinic waiting times and limited access in remote areas.
- **Implementation & Practical Work:** Defined the project scope: an informational multimodal assistant that allows users to speak their symptoms and submit photos/videos of skin conditions for preliminary guidance.
- **Key Outcome:** Clear project definition and established ethical boundaries (informational tool, not a diagnostic replacement).
---
### Day 02: Python 3.13 Setup & Virtual Environment Architecture
- **Domain:** Development Environment & Packaging
- **Concepts Covered:** Virtual environment isolation principles, dependency management, avoiding global package pollution. Comparison between traditional `venv`/`pip` and modern fast package managers like `uv`.
- **Implementation & Practical Work:** Initialized an isolated Python 3.13 virtual environment using `uv venv`. Configured `pyproject.toml` to declare dependencies and metadata for the project.
- **Key Outcome:** Reproducible, clean local development environment configured.
---
### Day 03: Version Control & GitHub Repository Structuring
- **Domain:** Software Engineering Best Practices
- **Concepts Covered:** Git version control workflow: staging, committing, branching, and synchronizing with remote repositories. Importance of commit history in tracking development progress.
- **Implementation & Practical Work:** Initialized local Git repository, created remote repository on GitHub, linked remote origin, and established initial directory architecture.
- **Key Outcome:** Version-controlled codebase ready for continuous development.
---
### Day 04: Configuration Security & Environment Variable Management
- **Domain:** Application Security & Secret Management
- **Concepts Covered:** 12-Factor App methodology regarding configuration separation. Risks associated with committing hardcoded API credentials to public repositories.
- **Implementation & Practical Work:** Implemented `python-dotenv` for reading environment variables. Created `.env.example` as a template and configured `.gitignore` to strictly exclude `.env` and local audio caches.
- **Key Outcome:** Secure credentials management safeguarding API tokens from accidental exposure.
---
### Day 05: Cloud Inference Platforms (Groq LPUs & Deepgram)
- **Domain:** Cloud AI Infrastructure & Low-Latency Inference
- **Concepts Covered:** Computational requirements of Large Language Models and Vision models. Why local consumer hardware struggles with real-time inference and how specialized LPUs (Language Processing Units) provide sub-second latency.
- **Implementation & Practical Work:** Configured developer accounts for Groq Cloud and Deepgram. Generated API authentication tokens and validated connectivity via basic Python test scripts.
- **Key Outcome:** Established verified API communication with cloud model inference backends.
---
### Day 06: End-to-End System Architecture & Data Flow Design
- **Domain:** System Design & Modular Software Architecture
- **Concepts Covered:** Modular software design principles: separation of concerns, decoupling audio ingestion, vision analysis, voice synthesis, and presentation layers.
- **Implementation & Practical Work:** Designed the 3-tier processing pipeline:
  1. *Patient Speech-to-Text* (`voice_of_patient.py`)
  2. *Vision & Clinical Reasoning* (`brain_of_the_doctor.py`)
  3. *Voice Synthesis* (`voice_of_the_doctor.py`)
  4. *Application Controller & UI* (`main.py`)
- **Key Outcome:** Architectural diagram finalized and individual module stubs created.
---
### Day 07: Digital Audio Representation & Audio Processing
- **Domain:** Audio Signal Processing Fundamentals
- **Concepts Covered:** Digital representation of sound: sample rate (e.g., 16kHz vs 44.1kHz), bit depth, channels (mono vs stereo), and audio formats (uncompressed WAV vs compressed MP3).
- **Implementation & Practical Work:** Explored Python audio file handling. Implemented file reading and buffer management functions to prepare recorded audio files for speech processing pipelines.
- **Key Outcome:** Solid foundation in digital audio requirements for machine learning models.
---
### Day 08: Automatic Speech Recognition (ASR) & OpenAI Whisper
- **Domain:** Speech-to-Text Architectures
- **Concepts Covered:** Transformer-based encoder-decoder architecture used in OpenAI Whisper. Model size trade-offs (`tiny`, `base`, `medium`, `large-v3`) in terms of parameters, latency, and transcription fidelity.
- **Implementation & Practical Work:** Analyzed Whisper's performance on medical and clinical terminology. Selected `whisper-large-v3` running on Groq for maximum transcription accuracy with millisecond response times.
- **Key Outcome:** Model selection finalized for the patient voice transcription component.
---
### Day 09: Implementing Patient Voice Transcription Module
- **Domain:** Audio API Integration
- **Concepts Covered:** File streaming over HTTP, multipart form uploads, handling binary audio file streams.
- **Implementation & Practical Work:** Developed `voice_of_patient.py`. Implemented `transcribe_patient_voice(audio_filepath)` using the Groq Python SDK (`client.audio.transcriptions.create`) to convert patient voice recordings into clean text.
- **Key Outcome:** Fully functional speech-to-text module accepting local audio files and returning transcripts.
---
### Day 10: Input Validation & Defensive Audio Handling
- **Domain:** Error Handling & Robustness
- **Concepts Covered:** Defensive programming: verifying file existence, validating file formats, and catching network timeouts or authentication failures before making external API requests.
- **Implementation & Practical Work:** Added validation checks in `voice_of_patient.py` to ensure the audio file exists and `GROQ_API_KEY` is present in the environment before triggering requests.
- **Key Outcome:** Robust audio ingestion module that fails gracefully with clear error messages.
---
### Day 11: Accent Robustness & Audio Quality Testing
- **Domain:** Model Evaluation & Empirical Testing
- **Concepts Covered:** Challenges in real-world ASR: acoustic variations, varying speech rates, ambient background noise, and international accents (such as Indian English).
- **Implementation & Practical Work:** Tested the transcription module with 5 diverse audio samples containing various background noise levels and complex medical descriptions (e.g., "erythema", "pruritus", "eczema").
- **Key Outcome:** Verified that `whisper-large-v3` maintains high accuracy across noisy conditions and clinical vocabulary.
---
### Day 12: Speech-to-Text Performance Benchmarking
- **Domain:** Latency Profiling & Optimization
- **Concepts Covered:** Measuring round-trip time (RTT) for cloud API requests and profiling network overhead versus inference latency.
- **Implementation & Practical Work:** Benchmarked the transcription module across multiple trials using Python's `time` library. Average response time was measured at under 1.2 seconds for 15-second audio recordings.
- **Key Outcome:** Performance profile documented, validating suitability for real-time conversational user experiences.
---
### Day 13: Digital Image Processing with Pillow (PIL)
- **Domain:** Image Preprocessing for Computer Vision
- **Concepts Covered:** Image data representation, dimensions, color spaces (RGB), in-memory byte streams, and the impact of image resolution on API upload speeds.
- **Implementation & Practical Work:** Wrote an image preprocessor using PIL: downscaling high-resolution skin photos to a maximum dimension of 1024x1024 while maintaining aspect ratio, and compressing to JPEG (quality 75) using `io.BytesIO`.
- **Key Outcome:** Memory-efficient image preprocessor that optimizes API payload size without losing critical diagnostic details.
---
### Day 14: Base64 Image Serialization for Vision APIs
- **Domain:** Web Serialization & Data URIs
- **Concepts Covered:** Base64 encoding mechanics: converting binary image data into standard ASCII characters for transmission inside JSON request bodies (`data:image/jpeg;base64,...`).
- **Implementation & Practical Work:** Developed `encode_image_for_groq()` in `brain_of_the_doctor.py` to convert in-memory PIL images directly to Base64 strings.
- **Key Outcome:** Reliable image encoder enabling direct transfer of image data to cloud vision models.
---
### Day 15: Video Processing & Frame Extraction with OpenCV
- **Domain:** Computer Vision & Video Stream Handling
- **Concepts Covered:** Video stream structure, decoding video frames, color format conversions (OpenCV's default BGR format to standard RGB).
- **Implementation & Practical Work:** Implemented `extract_frame_from_video()` using `cv2.VideoCapture`. The function reads the video file, extracts the first clear representative frame, converts BGR to RGB, and returns a PIL Image object.
- **Key Outcome:** Application support expanded to accept patient skin video clips in addition to static photos.
---
### Day 16: Prompt Engineering for Clinical AI Persona
- **Domain:** Prompt Design & LLM Conditioning
- **Concepts Covered:** System prompting, role assignment, output formatting constraints, and safety guidelines for healthcare assistants.
- **Implementation & Practical Work:** Formulated a structured system and user prompt directing the model to act as a calm, professional skin care specialist. Enforced a concise length of 2–3 sentences and banned special formatting characters (asterisks, bullet points) so the response translates smoothly into audio.
- **Key Outcome:** Reliable prompt template producing clear, spoken-friendly guidance.
---
### Day 17: Implementing Multimodal Vision LLM Integration
- **Domain:** Multimodal Large Language Models (MLLMs)
- **Concepts Covered:** Multimodal architectures combining textual token embeddings with visual patch embeddings to perform cross-modal reasoning.
- **Implementation & Practical Work:** Developed `brain_of_the_doctor()` in `brain_of_the_doctor.py`. Configured the Groq chat completions endpoint to accept both the patient transcript and base64-encoded visual media using Qwen Vision.
- **Key Outcome:** Core intelligence module functioning, capable of jointly analyzing patient symptom descriptions and skin photos.
---
### Day 18: Reasoning Model Output Sanitization (Regex Filtering)
- **Domain:** Text Post-Processing & Output Filtering
- **Concepts Covered:** Handling internal deliberation tags generated by modern reasoning models (such as `<think>...</think>`), which should remain hidden from the end user.
- **Implementation & Practical Work:** Integrated regex post-processing (`re.sub(r'<think>.*?(?:</think>|$)', '', content)`) to strip internal reasoning blocks before passing text to downstream speech synthesis.
- **Key Outcome:** Clean, polished doctor guidance free of internal model thinking artifacts.
---
### Day 19: Speech Synthesis Fundamentals (Text-to-Speech)
- **Domain:** Neural Audio Generation & Synthesis
- **Concepts Covered:** Evolution of speech synthesis from rule-based concatenative synthesis to neural vocoders. Evaluation criteria: natural prosody, breathing pauses, emotional inflection, and generation speed.
- **Implementation & Practical Work:** Researched and evaluated Text-to-Speech solutions, comparing cloud neural engines (Deepgram Aura) against local lightweight options (Google Text-to-Speech / gTTS).
- **Key Outcome:** Architectural decision to implement Deepgram Aura for the primary interface and retain gTTS as an offline fallback.
---
### Day 20: Fallback Speech Synthesis with gTTS
- **Domain:** Alternative Speech Generation & OS Audio Playback
- **Concepts Covered:** Cross-platform audio playback using native operating system commands (`SoundPlayer` in Windows, `afplay` in macOS, `aplay` in Linux).
- **Implementation & Practical Work:** Built `free_text_to_speech.py` implementing `text_to_speech_with_gtts()`. The script converts text to MP3 via Google Translate TTS and handles automatic playback across operating systems.
- **Key Outcome:** Working zero-cost fallback audio synthesis module.
---
### Day 21: Neural Text-to-Speech Integration with Deepgram Aura
- **Domain:** Cloud Neural Voice Generation
- **Concepts Covered:** Deepgram Aura SDK architecture, neural voice models (`aura-asteria-en`), streaming audio generation, and binary chunk writing.
- **Implementation & Practical Work:** Created `voice_of_the_doctor.py`. Implemented `convert_text_to_doctor_audio()` to generate realistic, professional spoken doctor guidance saved directly as `doctor_response.mp3`.
- **Key Outcome:** High-fidelity, natural doctor voice response generation module completed.
---
### Day 22: Payload Protection & Audio Buffer Management
- **Domain:** API Limits & Defensive Programming
- **Concepts Covered:** Character limitations on third-party speech endpoints (Deepgram limits requests to 2,000 characters), preventing network buffer overflows.
- **Implementation & Practical Work:** Implemented defensive text slicing (`text[:1999]`) and chunked file writing buffers in `voice_of_the_doctor.py`.
- **Key Outcome:** Resilient audio generation logic that prevents runtime crashes even when handling long clinical responses.
---
### Day 23: Headless Pipeline Integration & Testing
- **Domain:** Multi-Module Pipeline Verification
- **Concepts Covered:** Integration testing: verifying data compatibility across decoupled modules without depending on a graphical user interface.
- **Implementation & Practical Work:** Wrote an automated integration script chaining `voice_of_patient` ➔ `brain_of_the_doctor` ➔ `voice_of_the_doctor`. Verified full pipeline execution in under 4 seconds total round-trip time.
- **Key Outcome:** Verified seamless communication between Speech-to-Text, Vision LLM, and Text-to-Speech components.
---
### Day 24: Code Quality, Refactoring & PEP 8 Standards
- **Domain:** Software Quality Assurance
- **Concepts Covered:** Python style guidelines (PEP 8), modularity, explicit type hints, docstrings, and dead code elimination.
- **Implementation & Practical Work:** Conducted code audit across all project files. Cleaned package imports, verified consistent naming conventions, and ensured clear function documentation.
- **Key Outcome:** Maintainable, clean, production-ready codebase.
---
### Day 25: Web Interface Architecture with Gradio
- **Domain:** Machine Learning User Interfaces
- **Concepts Covered:** Principles of reactive web interfaces for ML models. Comparison of Gradio's component ecosystem versus traditional web frameworks (Flask/Django) for AI applications.
- **Implementation & Practical Work:** Structured the web layout in `main.py` using `gradio.Blocks`, defining input components for audio recording, image upload, and video upload.
- **Key Outcome:** Base interactive web interface scaffolded.
---
### Day 26: Developing the Master Pipeline Controller
- **Domain:** Application Controller Logic
- **Concepts Covered:** Event-driven architecture, event listeners (`.click()`), multi-input mapping, and user-facing exception handling in Gradio.
- **Implementation & Practical Work:** Implemented `process_inputs()` in `main.py`. The controller validates input presence (ensuring at least one audio recording and one visual media file exist) and coordinates sequential module execution.
- **Key Outcome:** Complete interactive pipeline connecting UI triggers to backend AI models.
---
### Day 27: UI/UX Styling & Clinical Aesthetic Customization
- **Domain:** Frontend Design & CSS Styling
- **Concepts Covered:** Custom CSS injection in Gradio, CSS custom properties (variables), modern typography (Inter font), responsive layouts, and medical interface design.
- **Implementation & Practical Work:** Designed and injected custom CSS for `main.py`: styled header badges, consultation cards, responsive media rows, customized button gradients, and audio players.
- **Key Outcome:** Professional, medical-grade consultation web interface.
---
### Day 28: Medical AI Ethics, Safeguards & Disclaimers
- **Domain:** AI Safety & Healthcare Compliance
- **Concepts Covered:** Ethical AI deployment: liability management, avoiding unauthorized medical diagnoses, user expectations, and mandatory disclaimers.
- **Implementation & Practical Work:** Integrated clear medical disclaimers into the web UI header, footer, and README. Confirmed that all system prompts explicitly direct patients to consult certified dermatologists for formal diagnosis.
- **Key Outcome:** Ethically responsible application compliant with academic and industry standards.
---
### Day 29: System Testing & Edge Case Validation
- **Domain:** Comprehensive System Testing
- **Concepts Covered:** Black-box testing, boundary value testing, handling diverse skin tones and image qualities, and verifying system behavior during network or API disruptions.
- **Implementation & Practical Work:** Executed end-to-end tests using sample skin condition images from `Test data/` (rashes, dry patches, acne). Tested recovery behavior when microphones are muted or invalid API keys are supplied.
- **Key Outcome:** Reliable, validated application demonstrating robust performance across real-world edge cases.
---
### Day 30: Final Documentation, GitHub Packaging & Submission
- **Domain:** Technical Documentation & Project Release
- **Concepts Covered:** Writing comprehensive technical documentation, architecture documentation, setup instructions, and finalizing the project for formal academic submission.
- **Implementation & Practical Work:** Finalized technical documentation, organized project dependencies, verified clean Git commits, and compiled the complete 30-day training progress report.
- **Key Outcome:** 30-day training requirements completed, fully documented on GitHub, and ready for minor project evaluation.
