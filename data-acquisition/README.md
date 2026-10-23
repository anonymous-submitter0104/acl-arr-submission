# Data Acquisition

This section outlines our **data acquisition strategy**, describing the **sources, collection methodology, and filtering criteria** used to build the initial corpus. It also highlights the rationale behind selecting specific datasets, ensuring both **diversity** and **relevance** to downstream tasks.

This folder accompanies the anonymous ACL ARR submission *MILA (Multilingual Indic Language Archive): A Dataset for Equitable Multilingual LLMs*. See Section 3.1 (Data Acquisition and Governance) and Appendix E of the paper for the full acquisition methodology, source audits and statistics.

## How this folder relates to the paper

MILA's acquisition pipeline combines three strands:

* **Large-scale web crawling** of multilingual websites, forums and academic repositories, using high-concurrency, source-specific crawlers (the scrapers documented below).
* **Institutional and archival digitization**, mainly curated books from Archive.org, curriculum-aligned materials from the National Digital Library of India (NDLI), and Wikimedia projects (Appendix E.1–E.3).
* **License-compliant open datasets**, including over 1,700 open datasets from Hugging Face.

All sources are normalized under a unified provenance framework: standardized metadata (ISBN / DOI / archive IDs), URL and MD5 deduplication, and record-level identifiers for traceability. Each item carries licensing metadata, and items with restrictive or ambiguous licenses are excluded from the open release (Appendix E and Appendix F.2). Downstream curation (language identification, quality and toxicity filtering, PII redaction, decontamination) is described in Appendix B and the `data-curation` folder.

> **Scope note.** The scrapers below are the source-specific crawlers shipped in this folder. The Archive.org, Wikimedia and metadata-first infrastructure for large collections is described in Appendix E.1, E.3 and E.4 of the paper. Throughput and quality figures in the "Performance Metrics" section are indicative engineering estimates for these scripts and are not results reported in the paper.

---
# Table of Contents

* [Web Crawlers & Scrapers](#web-crawlers--scrapers)

  * [🎯 Overview](#-overview)
  * [📁 Scrapers Collection](#-scrapers-collection)

    * [🔧 GeeksforGeeks Scraper (`gfg_scraper.py`)](#-geeksforgeeks-scraper-gfg_scraperpy)
    * [🌐 Common Crawl WARC Extractor (`common_crawl_url_warc_to_text.py`)](#-common-crawl-warc-extractor-common_crawl_url_warc_to_textpy)
    * [📚 NDLI High School Scraper (`ndli_highschool.py`)](#-ndli-high-school-scraper-ndli_highschoolpy)
    * [🧮 AIME Mathematics Scraper (`aimim.py`)](#-aime-mathematics-scraper-aimimpy)
    * [📚 Gadhkosh Literature Scraper (`gadhkosh.py`)](#-gadhkosh-literature-scraper-gadhkoshpy)
    * [🏛️ IRADAI Research Scraper (`iradai.py`)](#-iradai-research-scraper-iradaipy)
    * [💼 SEBI Financial Document Scraper (`sebi/scrp.py`)](#-sebi-financial-document-scraper-sebiscrppy)
  * [🚀 Usage & Configuration](#-usage--configuration)

    * [Basic Usage](#basic-usage)
    * [Advanced Configuration](#advanced-configuration)

      * [Environment Setup](#environment-setup)
      * [Common Crawl Configuration](#common-crawl-configuration)
      * [Scrapy Settings](#scrapy-settings)
  * [🔍 Quality Assurance Features](#-quality-assurance-features)

    * [Content Validation](#content-validation)
    * [Error Handling](#error-handling)
    * [Ethical Scraping](#ethical-scraping)
  * [📊 Performance Metrics](#-performance-metrics)

    * [Processing Capabilities](#processing-capabilities)
    * [Quality Benchmarks](#quality-benchmarks)
  * [🔄 Integration with Data Pipeline](#-integration-with-data-pipeline)

    * [Upstream Integration](#upstream-integration)
    * [Output Standardization](#output-standardization)
    * [Downstream Processing](#downstream-processing)
  * [🛠️ Technical Architecture](#️-technical-architecture)

    * [Async Processing (Common Crawl)](#async-processing-common-crawl)
    * [Scrapy Integration (NDLI, AIME)](#scrapy-integration-ndli-aime)
    * [Content Processing Pipeline](#content-processing-pipeline)
  * [📚 Dependencies](#-dependencies)

    * [Core Libraries](#core-libraries)
    * [System Requirements](#system-requirements)
  * [🔮 Future Enhancements](#-future-enhancements)

    * [Planned Features](#planned-features)
    * [Performance Improvements](#performance-improvements)
   

# Web Crawlers & Scrapers

Advanced collection of specialized web scrapers designed for high-quality educational and technical content extraction. These scrapers are optimized for LLM training data collection with built-in quality filtering, language detection, and content structuring capabilities.

## 🎯 Overview

This module provides production-ready scrapers for acquiring structured educational content from major platforms. Each scraper includes advanced features like content cleaning, metadata extraction, duplicate detection, and quality assessment.

**Key Features:**
- **Async Processing**: High-performance concurrent scraping
- **Quality Filtering**: Built-in content quality assessment
- **Language Detection**: Multi-language support with FastText
- **Error Recovery**: Robust error handling and retry mechanisms
- **Structured Output**: Consistent JSONL output format
- **Rate Limiting**: Ethical scraping with configurable delays

## 📁 Scrapers Collection

### 🔧 GeeksforGeeks Scraper (`gfg_scraper.py`)
**Advanced programming content extraction with structured data organization**

**Target**: Programming tutorials, algorithms, data structures, and computer science articles
**Technology**: Python with BeautifulSoup, Requests
**Output Format**: Structured JSONL with metadata

**Key Features:**
- **Content Structuring**: Separates problem statements, solutions, and code examples
- **Code Extraction**: Preserves code formatting and syntax highlighting
- **Example Parsing**: Extracts input/output examples with proper formatting
- **Text Cleaning**: Advanced text normalization and cleaning
- **Metadata Extraction**: Article title, difficulty, category, tags
- **Session Management**: Persistent sessions with proper headers

**Data Structure:**
```json
{
  "url": "article_url",
  "title": "Article Title", 
  "content": "Cleaned main content",
  "code_examples": ["code1", "code2"],
  "examples": [{"input": "...", "output": "..."}],
  "metadata": {"category": "...", "difficulty": "..."}
}
```

**Usage:**
```bash
python gfg_scraper.py --category algorithms --max-articles 1000
```

### 🌐 Common Crawl WARC Extractor (`common_crawl_url_warc_to_text.py`)
**Large-scale web text extraction with language detection and quality scoring**

**Target**: Web text from Common Crawl WARC files
**Technology**: AsyncIO, AIOHTTP, FastText, Trafilatura, JusText
**Processing Scale**: 100+ concurrent connections

**Advanced Features:**
- **Async Architecture**: Process 100+ WARC records concurrently
- **Multi-Engine Text Extraction**: Trafilatura + JusText for optimal content extraction
- **Language Detection**: FastText and langdetect with confidence scoring
- **Quality Assessment**: Content quality scoring based on multiple metrics
- **Duplicate Detection**: Hash-based duplicate content identification
- **Memory Management**: Efficient streaming processing for large WARC files
- **Progress Tracking**: Real-time processing statistics and logging

**Processing Pipeline:**
```
WARC Records → URL Extraction → Content Download → Text Extraction → 
Language Detection → Quality Scoring → Deduplication → JSONL Output
```

**Configuration:**
- `MAX_CONCURRENT`: 100 (adjustable based on system resources)
- `OUTPUT_FILE`: Configurable output paths
- `MY_AGENT`: Custom user agent for ethical crawling

**Output Format:**
```json
{
  "url": "source_url",
  "text": "extracted_content",
  "language": "detected_language",
  "confidence": 0.95,
  "quality_score": 0.87,
  "extraction_method": "trafilatura",
  "timestamp": "2025-09-30T10:30:00Z"
}
```

### 📚 NDLI High School Scraper (`ndli_highschool.py`)
**Educational content extraction from National Digital Library of India**

**Target**: High school educational materials, textbooks, and learning resources
**Technology**: Scrapy framework with advanced spider features
**Focus**: Punjab School Education Board and other regional content

**Specialized Features:**
- **AJAX Integration**: Handles dynamic content loading via AJAX requests
- **Educational Taxonomy**: Automatically categorizes content by subject and grade
- **Multi-language Support**: Processes content in Hindi and regional languages
- **Resource Type Filtering**: Focuses on educational materials (textbooks, guides)
- **Metadata Preservation**: Maintains educational context and curriculum alignment
- **Batch Processing**: Handles large collections of educational resources

**Spider Configuration:**
```python
custom_settings = {
    "CONCURRENT_REQUESTS": 100,
    "CONCURRENT_REQUESTS_PER_DOMAIN": 100,
    "DOWNLOAD_TIMEOUT": 10000,
    "DOWNLOAD_MAXSIZE": 0,
}
```

**Target Content Types:**
- Textbooks and reference materials
- Educational guides and tutorials
- Curriculum-aligned content
- Multi-subject academic resources

### 🧮 AIME Mathematics Scraper (`aimim.py`)
**Competition mathematics problems and solutions extraction**

**Target**: American Invitational Mathematics Examination problems and solutions
**Technology**: Scrapy with specialized mathematical content parsing
**Source**: Art of Problem Solving (AoPS) wiki

**Mathematical Content Features:**
- **Problem-Solution Pairing**: Maintains problem-solution relationships
- **Mathematical Notation**: Preserves LaTeX and mathematical formatting
- **Year-wise Organization**: Chronological problem organization
- **Difficulty Classification**: Implicit difficulty through competition tier
- **Solution Validation**: Multiple solution approaches when available
- **Cross-referencing**: Links to related problems and concepts

**Content Structure:**
```json
{
  "year": "2023",
  "problem_number": "15",
  "problem_statement": "Mathematical problem text...",
  "solution": "Detailed solution with steps...",
  "difficulty": "high",
  "topics": ["geometry", "algebra"],
  "source_url": "aops_wiki_url"
}
```

**Spider Features:**
- **Intelligent Navigation**: Follows year and problem links automatically
- **Content Validation**: Verifies problem-solution completeness
- **Rate Limiting**: Respectful crawling with delays
- **Error Recovery**: Handles missing or malformed content gracefully

### 📚 Gadhkosh Literature Scraper (`gadhkosh.py`)
**Hindi literature and cultural content extraction**

**Target**: Hindi literature, poetry, stories, and cultural texts
**Technology**: Scrapy CrawlSpider with LinkExtractor
**Source**: Gadhkosh.org literary archive

**Literary Content Features:**
- **Content Categorization**: Automatic categorization by genre and author
- **Text Preservation**: Maintains original formatting and literary structure
- **Cultural Context**: Preserves cultural and historical context
- **Multi-genre Support**: Poetry, prose, essays, and traditional texts
- **Author Metadata**: Author information and biographical details
- **Publication History**: Publication dates and source information

### 🏛️ IRADAI Research Scraper (`iradai.py`)
**Regional language research and academic content extraction**

**Target**: Research papers, academic content, and regional language materials
**Technology**: Advanced Scrapy spider with caching and optimization
**Focus**: Academic and research institutions content

**Research Features:**
- **Academic Filtering**: Focuses on peer-reviewed and academic content
- **Multi-language Support**: Regional languages with proper encoding
- **Citation Preservation**: Maintains academic citations and references
- **Document Classification**: Automatic classification by research domain
- **Quality Assessment**: Academic quality scoring and validation
- **Institutional Tracking**: Source institution and department information

### 💼 SEBI Financial Document Scraper (`sebi/scrp.py`)
**Financial regulations and compliance document extraction**

**Target**: SEBI regulations, compliance documents, and financial guidelines
**Technology**: Specialized Scrapy spider with helper modules
**Source**: Securities and Exchange Board of India (SEBI)

**Financial Content Features:**
- **Regulatory Categorization**: Classification by regulation type and sector
- **Document Versioning**: Tracking of regulation updates and amendments
- **Compliance Mapping**: Links between related regulatory documents
- **Date Tracking**: Effective dates, publication dates, and revision history
- **Legal Structure**: Preservation of legal document structure and formatting
- **Cross-references**: Links to related regulations and guidelines

## 🚀 Usage & Configuration

### Basic Usage
```bash
# GeeksforGeeks Scraper
python gfg_scraper.py

# Common Crawl Extractor (requires PARQUET_PATH configuration)
python common_crawl_url_warc_to_text.py

# NDLI Educational Content
scrapy crawl NDLI -o ndli_content.jsonl

# AIME Mathematics Problems
scrapy crawl aime -o aime_problems.jsonl
```

### Advanced Configuration

#### Environment Setup
```bash
# Install dependencies
pip install scrapy beautifulsoup4 requests aiohttp
pip install fasttext langdetect trafilatura justext
pip install warcio pandas

# Download FastText language model
wget https://dl.fbaipublicfiles.com/fasttext/supervised-models/lid.176.bin
```

#### Common Crawl Configuration
```python
# Configuration variables in common_crawl_url_warc_to_text.py
PARQUET_PATH = "data/part-00288-88b30a59-3c73-48ba-a167-077611bfd245.c000.gz.parquet"  # DEFAULT
# PARQUET_PATH = "path_to_common_crawl_index.parquet"  # or point to your own Common Crawl index
MAX_CONCURRENT = 100  # Adjust based on system resources
OUTPUT_FILE = "./warc_text_output/extracted_text.jsonl"
```

#### Scrapy Settings
```python
# Custom settings for educational scrapers
CUSTOM_SETTINGS = {
    'CONCURRENT_REQUESTS': 100,
    'DOWNLOAD_DELAY': 1,
    'RANDOMIZE_DOWNLOAD_DELAY': 0.5,
    'USER_AGENT': 'Educational-Content-Scraper/1.0'
}
```

## 🔍 Quality Assurance Features

### Content Validation
- **Text Quality Metrics**: Length, coherence, educational value assessment
- **Language Confidence**: High-confidence language detection (>0.8)
- **Duplicate Detection**: Content hash-based deduplication
- **Format Validation**: Ensures proper JSON/JSONL output structure

### Error Handling
- **Network Resilience**: Automatic retry with exponential backoff
- **Content Validation**: Graceful handling of malformed content
- **Logging System**: Comprehensive operation logging
- **Progress Tracking**: Real-time processing statistics

### Ethical Scraping
- **Rate Limiting**: Configurable delays between requests
- **Identifiable User Agent**: Scrapers identify themselves to servers via a configurable user agent
- **Resource Management**: Efficient memory and connection usage

## 📊 Performance Metrics

> Indicative engineering estimates for the scripts in this folder; these are not results reported in the paper and depend on hardware, network and target-site behavior.

### Processing Capabilities
- **GeeksforGeeks**: ~500 articles/hour with quality filtering
- **Common Crawl**: 100+ concurrent WARC record processing
- **NDLI**: ~1000 educational documents/hour
- **AIME**: Complete competition year processing in ~30 minutes

### Quality Benchmarks
- **Language Detection Accuracy**: >95% for supported languages
- **Content Quality Score**: Average >0.8 for educational content
- **Deduplication Rate**: ~10-15% duplicate detection across sources
- **Text Extraction Accuracy**: >90% content preservation

## 🔄 Integration with Data Pipeline

### Upstream Integration
- **Data Acquisition**: Feeds into main acquisition pipeline
- **Quality Filtering**: Integrates with Data Curation module
- **Language Routing**: Supports multilingual processing workflows

### Output Standardization
- **Consistent Format**: Standardized JSONL output across all scrapers
- **Metadata Schema**: Common metadata fields for integration
- **Quality Metrics**: Embedded quality scores for downstream filtering

### Downstream Processing
- **Curation Ready**: Output format compatible with NeMo-Curator
- **Translation Ready**: Structured for translation pipeline input
- **Storage Ready**: Formatted for JuiceFS/DataHub ingestion

## 🛠️ Technical Architecture

### Async Processing (Common Crawl)
```python
async def process_warc_record(session, warc_record):
    # Async processing with aiohttp
    async with session.get(url) as response:
        content = await response.text()
        return extract_and_score_content(content)
```

### Scrapy Integration (NDLI, AIME)
```python
class EducationalSpider(scrapy.Spider):
    custom_settings = {
        'CONCURRENT_REQUESTS': 100,
        'DOWNLOAD_TIMEOUT': 10000,
    }
```

### Content Processing Pipeline
```python
def process_content(raw_content):
    cleaned = clean_text(raw_content)
    language = detect_language(cleaned)
    quality = assess_quality(cleaned)
    return structured_output(cleaned, language, quality)
```

## 📚 Dependencies

### Core Libraries
```bash
# Web scraping
scrapy>=2.5.0
beautifulsoup4>=4.9.0
requests>=2.25.0

# Async processing  
aiohttp>=3.8.0
aiofiles>=0.7.0

# Text processing
trafilatura>=1.2.0
justext>=3.0.0
fasttext>=0.9.2
langdetect>=1.0.9

# Data handling
pandas>=1.3.0
warcio>=1.7.0
```

### System Requirements
- **Python**: 3.8+
- **Memory**: 4GB+ recommended for Common Crawl processing
- **Storage**: SSD recommended for high-throughput processing
- **Network**: Stable internet connection for optimal performance

## 🔮 Future Enhancements

### Planned Features
- **Real-time Processing**: Live content monitoring and extraction
- **ML-based Quality Assessment**: Advanced content quality scoring
- **Auto-categorization**: AI-powered content classification
- **Multi-site Orchestration**: Coordinated multi-platform scraping

### Performance Improvements
- **Distributed Processing**: Multi-node scraping coordination
- **Intelligent Rate Limiting**: Adaptive delay based on server response
- **Content Caching**: Intelligent content caching and refresh
- **Pipeline Optimization**: Streamlined processing workflows

---

For detailed usage examples and troubleshooting, see the individual scraper files and main Data Acquisition documentation.
