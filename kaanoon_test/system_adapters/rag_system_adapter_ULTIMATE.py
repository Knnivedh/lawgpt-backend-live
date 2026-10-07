"""
ULTIMATE RAG ADAPTER - Designed for 80%+ Accuracy
Key Features:
1. Smart extraction from Kaanoon Q&A when retrieved
2. Concise, direct answer generation (not verbose legal opinions)
3. Optimized context selection (top 3 docs, high relevance only)
4. Adaptive prompting based on question type
"""

import sys
import os
import sys
# Debug print to confirm loading of modified file
print(f"LOADING ULTIMATE ADAPTER FROM: {__file__}", file=sys.stderr, flush=True)
from pathlib import Path
from typing import Dict, Any, List, Tuple
import time
import re
import json
from datetime import datetime
from dotenv import load_dotenv
import requests

HI_ENFORCEMENT_PATCH_MARKER = "hi-enforcement-20260403-v3"

# Import Input Analysis Engine
try:
    from .input_analysis_engine import InputAnalysisEngine
    INPUT_ANALYSIS_AVAILABLE = True
except ImportError:
    INPUT_ANALYSIS_AVAILABLE = False
    print("[WARNING] Input Analysis Engine not available")

# Import Legal Reasoning Engine
# Import Legal Reasoning Engine
try:
    from kaanoon_test.reasoning import get_legal_reasoning_engine
    REASONING_ENGINE_AVAILABLE = True
except ImportError as e:
    REASONING_ENGINE_AVAILABLE = False
    print(f"[WARNING] Legal Reasoning Engine not available: {e}")

# Add parent directories to path
project_root = Path(__file__).parent.parent.parent
sys.path.insert(0, str(project_root))

# Load environment variables from config/.env
load_dotenv(project_root / "config" / ".env")

try:
    from rag_system.core.enhanced_retriever import EnhancedRetriever
    _ENHANCED_RETRIEVER_AVAILABLE = True
except ImportError as e:
    _ENHANCED_RETRIEVER_AVAILABLE = False
    EnhancedRetriever = None
    print(f"[WARNING] EnhancedRetriever not available: {e}")

try:
    from config.config import Config
    _CONFIG_AVAILABLE = True
except ImportError as e:
    _CONFIG_AVAILABLE = False
    Config = None
    print(f"[WARNING] Config not available: {e}")

try:
    from openai import OpenAI
    _OPENAI_AVAILABLE = True
except ImportError as e:
    _OPENAI_AVAILABLE = False
    OpenAI = None
    print(f"[WARNING] OpenAI not available: {e}")

# chromadb is disabled on cloud — guard it so the server starts without it
try:
    from rag_system.core.hybrid_chroma_store import HybridChromaStore
    _CHROMADB_AVAILABLE = True
except ImportError:
    _CHROMADB_AVAILABLE = False
    HybridChromaStore = None

# Import enhancement utilities
try:
    from kaanoon_test.utils.metadata_extractor import MetadataExtractor
    from kaanoon_test.utils.timeline_builder import TimelineBuilder
    ENHANCEMENT_UTILS_AVAILABLE = True
except ImportError as e:
    ENHANCEMENT_UTILS_AVAILABLE = False
    print(f"[WARNING] Enhancement utilities not available: {e}")


class SimpleWebSearchClient:
    """ULTRA-POWERFUL web search client with 10+ sources and parallel searching."""
    
    def __init__(self):
        self.headers = {
            'User-Agent': 'Mozilla/5.0 (Windows NT 10.0; Win64; x64) AppleWebKit/537.36 (KHTML, like Gecko) Chrome/120.0.0.0 Safari/537.36'
        }
        self.timeout = 15
        self.serper_api_key = os.getenv('SERPER_API_KEY')
        self.newsapi_key = os.getenv('NEWSAPI_KEY')  # Free: 100 req/day
        self.bing_api_key = os.getenv('BING_SEARCH_KEY')  # Free: 1000 req/month
        
        # Try to import duckduckgo-search library
        self.ddgs_available = False
        self.ddgs = None
        try:
            import warnings
            with warnings.catch_warnings():
                warnings.simplefilter("ignore")
                try:
                    from ddgs import DDGS
                except ImportError:
                    from duckduckgo_search import DDGS
                self.ddgs = DDGS(timeout=20)
            self.ddgs_available = True
            print("[WEB SEARCH] DuckDuckGo search library initialized")
        except ImportError as e:
            print(f"[WEB SEARCH] duckduckgo-search library not available: {e}")
        except Exception as e:
            print(f"[WEB SEARCH] DDGS initialization failed: {e}")
    
    def search_bing_news(self, query: str, max_results: int = 10) -> List[Dict]:
        """Search Bing News API (free: 1000 req/month)"""
        if not self.bing_api_key:
            print("[WEB SEARCH] Bing API key not found")
            return []
        
        try:
            import urllib.parse
            encoded_query = urllib.parse.quote(query)
            
            url = f"https://api.bing.microsoft.com/v7.0/news/search?q={encoded_query}&count={max_results}&mkt=en-IN"
            headers = {
                **self.headers,
                'Ocp-Apim-Subscription-Key': self.bing_api_key
            }
            
            resp = requests.get(url, headers=headers, timeout=self.timeout)
            resp.raise_for_status()
            data = resp.json()
            
            results = []
            for article in data.get('value', [])[:max_results]:
                results.append({
                    'title': article.get('name', ''),
                    'url': article.get('url', ''),
                    'snippet': article.get('description', ''),
                    'source': f"bing_news ({article.get('provider', [{}])[0].get('name', 'news')})",
                    'published': article.get('datePublished', '')
                })
            
            print(f"[WEB SEARCH] Bing News returned {len(results)} results")
            return results
            
        except Exception as e:
            print(f"[WEB SEARCH] Bing News failed: {e}")
            return []
    
    def search_reddit_rss(self, query: str, max_results: int = 5) -> List[Dict]:
        """Search Reddit via RSS (free, no API key!)"""
        try:
            import urllib.parse
            import xml.etree.ElementTree as ET
            
            encoded_query = urllib.parse.quote(query)
            
            # Reddit search RSS
            url = f"https://www.reddit.com/search.rss?q={encoded_query}&sort=new&limit={max_results}"
            
            resp = requests.get(url, headers=self.headers, timeout=self.timeout)
            resp.raise_for_status()
            
            root = ET.fromstring(resp.content)
            results = []
            
            for entry in root.findall('.//{http://www.w3.org/2005/Atom}entry')[:max_results]:
                title = entry.find('{http://www.w3.org/2005/Atom}title')
                link = entry.find('{http://www.w3.org/2005/Atom}link')
                content = entry.find('{http://www.w3.org/2005/Atom}content')
                
                results.append({
                    'title': title.text if title is not None else '',
                    'url': link.get('href') if link is not None else '',
                    'snippet': content.text[:300] if content is not None else '',
                    'source': 'reddit'
                })
            
            print(f"[WEB SEARCH] Reddit RSS returned {len(results)} results")
            return results
            
        except Exception as e:
            print(f"[WEB SEARCH] Reddit RSS failed: {e}")
            return []
    
    def search_newsapi(self, query: str, max_results: int = 10) -> List[Dict]:
        """Search NewsAPI for current news (free tier: 100 req/day)"""
        if not self.newsapi_key:
            print("[WEB SEARCH] NewsAPI key not found")
            return []
        
        try:
            import urllib.parse
            encoded_query = urllib.parse.quote(query)
            
            # NewsAPI endpoint (free tier)
            url = f"https://newsapi.org/v2/everything?q={encoded_query}&sortBy=publishedAt&language=en&pageSize={max_results}&apiKey={self.newsapi_key}"
            
            resp = requests.get(url, headers=self.headers, timeout=self.timeout)
            resp.raise_for_status()
            data = resp.json()
            
            results = []
            if data.get('status') == 'ok':
                for article in data.get('articles', [])[:max_results]:
                    results.append({
                        'title': article.get('title', ''),
                        'url': article.get('url', ''),
                        'snippet': article.get('description', '') or article.get('content', '')[:300],
                        'source': f"newsapi ({article.get('source', {}).get('name', 'news')})",
                        'published': article.get('publishedAt', ''),
                        'image': article.get('urlToImage', '')
                    })
            
            print(f"[WEB SEARCH] NewsAPI returned {len(results)} results")
            return results
            
        except Exception as e:
            print(f"[WEB SEARCH] NewsAPI failed: {e}")
            return []
    
    def search_google_news_rss(self, query: str, max_results: int = 10) -> List[Dict]:
        """Search Google News RSS (free, no API key needed!)"""
        try:
            import urllib.parse
            import xml.etree.ElementTree as ET
            
            encoded_query = urllib.parse.quote(query)
            
            # Google News RSS feed
            url = f"https://news.google.com/rss/search?q={encoded_query}&hl=en-IN&gl=IN&ceid=IN:en"
            
            resp = requests.get(url, headers=self.headers, timeout=self.timeout)
            resp.raise_for_status()
            
            # Parse RSS XML
            root = ET.fromstring(resp.content)
            results = []
            
            # Find all items in RSS feed
            for item in root.findall('.//item')[:max_results]:
                title = item.find('title')
                link = item.find('link')
                description = item.find('description')
                pub_date = item.find('pubDate')
                
                results.append({
                    'title': title.text if title is not None else '',
                    'url': link.text if link is not None else '',
                    'snippet': description.text if description is not None else '',
                    'source': 'google_news',
                    'published': pub_date.text if pub_date is not None else ''
                })
            
            print(f"[WEB SEARCH] Google News RSS returned {len(results)} results")
            return results
            
        except Exception as e:
            print(f"[WEB SEARCH] Google News RSS failed: {e}")
            return []
    
    def search_with_requests(self, query: str, max_results: int = 10) -> List[Dict]:
        """Fallback search using direct requests to search engines."""
        results = []
        
        try:
            # Try Brave Search API (free tier available)
            # For now, use a simple HTML scraping approach as fallback
            import urllib.parse
            encoded_query = urllib.parse.quote_plus(query)
            
            # Try DuckDuckGo Instant Answer API (free, no key needed)
            ddg_api_url = f"https://api.duckduckgo.com/?q={encoded_query}&format=json"
            resp = requests.get(ddg_api_url, headers=self.headers, timeout=self.timeout)
            
            if resp.status_code == 200:
                data = resp.json()
                
                # Get related topics
                for topic in data.get('RelatedTopics', [])[:max_results]:
                    if isinstance(topic, dict) and 'Text' in topic:
                        results.append({
                            'title': topic.get('Text', '')[:100],
                            'url': topic.get('FirstURL', ''),
                            'snippet': topic.get('Text', ''),
                            'source': 'duckduckgo_api'
                        })
                
                # Get abstract if available
                if data.get('Abstract'):
                    results.insert(0, {
                        'title': data.get('Heading', query),
                        'url': data.get('AbstractURL', ''),
                        'snippet': data.get('Abstract', ''),
                        'source': 'duckduckgo_api'
                    })
            
            print(f"[WEB SEARCH] DuckDuckGo API returned {len(results)} results")
            
        except Exception as e:
            print(f"[WEB SEARCH] Fallback search failed: {e}")
        
        return results
    
    def search_wikipedia(self, query: str, max_results: int = 5) -> List[Dict]:
        """Search Wikipedia for reliable information (always works!)"""
        results = []
        
        try:
            import urllib.parse
            encoded_query = urllib.parse.quote(query)
            
            # Wikipedia Search API
            search_url = f"https://en.wikipedia.org/w/api.php?action=opensearch&search={encoded_query}&limit={max_results}&format=json"
            resp = requests.get(search_url, headers=self.headers, timeout=self.timeout)
            
            if resp.status_code == 200:
                data = resp.json()
                # Format: [query, [titles], [descriptions], [urls]]
                if len(data) >= 4:
                    titles = data[1]
                    descriptions = data[2]
                    urls = data[3]
                    
                    for i in range(min(len(titles), max_results)):
                        if titles[i] and urls[i]:
                            results.append({
                                'title': titles[i],
                                'url': urls[i],
                                'snippet': descriptions[i] if i < len(descriptions) else f"Wikipedia article about {titles[i]}",
                                'source': 'wikipedia'
                            })
            
            print(f"[WEB SEARCH] Wikipedia returned {len(results)} results")
            
        except Exception as e:
            print(f"[WEB SEARCH] Wikipedia search failed: {e}")
        
        return results
    
    def search_duckduckgo(self, query: str, max_results: int = 15) -> List[Dict]:
        """ULTRA-POWERFUL parallel search across ALL sources for MAXIMUM speed and coverage!"""
        import concurrent.futures
        import threading
        
        print(f"\n{'='*80}")
        print(f"🚀 ULTRA WEB SEARCH ACTIVATED: {query}")
        print(f"{'='*80}\n")
        
        all_results = []
        results_lock = threading.Lock()
        
        def safe_search(search_func, *args, **kwargs):
            """Thread-safe search wrapper"""
            try:
                results = search_func(*args, **kwargs)
                if results:
                    with results_lock:
                        all_results.extend(results)
            except Exception as e:
                print(f"[WEB SEARCH] {search_func.__name__} error: {e}")
        
        # Launch ALL searches in PARALLEL for maximum speed!
        with concurrent.futures.ThreadPoolExecutor(max_workers=8) as executor:
            futures = []
            
            # Tier 1: News Sources (prioritized)
            futures.append(executor.submit(safe_search, self.search_google_news_rss, query, 8))
            
            if self.newsapi_key:
                futures.append(executor.submit(safe_search, self.search_newsapi, query, 8))
            
            if self.bing_api_key:
                futures.append(executor.submit(safe_search, self.search_bing_news, query, 8))
            
            # Tier 2: General Web
            if self.ddgs_available and self.ddgs:
                futures.append(executor.submit(safe_search, self._ddg_library_search, query, 10))
            
            futures.append(executor.submit(safe_search, self.search_with_requests, query, 8))
            
            # Tier 3: Community & Knowledge
            futures.append(executor.submit(safe_search, self.search_reddit_rss, query, 5))
            futures.append(executor.submit(safe_search, self.search_wikipedia, query, 5))
            
            # Wait for all searches to complete (with timeout)
            concurrent.futures.wait(futures, timeout=10)
        
        print(f"\n[WEB SEARCH] Parallel search complete!")
        print(f"[WEB SEARCH] Total raw results: {len(all_results)}")
        
        # Smart deduplication and ranking
        seen_urls = set()
        unique_results = []
        source_counts = {}
        
        for result in all_results:
            url = result.get('url', '')
            if not url or url in seen_urls:
                continue
            
            seen_urls.add(url)
            unique_results.append(result)
            
            # Track source diversity
            source = result.get('source', 'unknown')
            source_counts[source] = source_counts.get(source, 0) + 1
        
        # Prioritize news sources for current events
        def rank_result(r):
            source = r.get('source', '')
            score = 0
            
            # Boost news sources
            if 'news' in source.lower():
                score += 100
            if 'google_news' in source:
                score += 50
            if 'bing' in source:
                score += 40
            if 'newsapi' in source:
                score += 40
            
            # Boost recent results  
            if r.get('published'):
                score += 30
            
            # Boost Reddit for discussions
            if 'reddit' in source:
                score += 20
            
            # General web search
            if 'duckduckgo' in source:
                score += 10
            
            # Wikipedia for context
            if 'wikipedia' in source:
                score += 5
            
            return score
        
        # Sort by relevance/recency
        unique_results.sort(key=rank_result, reverse=True)
        
        # Keep top results
        final_results = unique_results[:max_results]
        
        print(f"[WEB SEARCH] Unique results: {len(unique_results)}")
        print(f"[WEB SEARCH] Sources used: {', '.join(source_counts.keys())}")
        print(f"[WEB SEARCH] Returning top {len(final_results)} results")
        print(f"{'='*80}\n")
        
        # Fallback if nothing found
        if not final_results:
            print("[WEB SEARCH] ⚠️ No results from any source, generating fallback")
            final_results = [{
                'title': f'Web search attempted for: {query}',
                'url': f'https://www.google.com/search?q={query.replace(" ", "+")}',
                'snippet': 'Searched 8+ sources but found limited results. Try the Google search link for more options.',
                'source': 'system_fallback'
            }]
        
        return final_results
    
    def _ddg_library_search(self, query: str, max_results: int) -> List[Dict]:
        """Helper for DuckDuckGo library search (for threading)"""
        if not self.ddgs_available or not self.ddgs:
            return []
        
        try:
            try:
                ddg_iter = self.ddgs.text(
                    query,
                    max_results=max_results,
                    region='wt-wt',
                    safesearch='moderate',
                    timelimit=None
                )
            except TypeError:
                ddg_iter = self.ddgs.text(
                    keywords=query,
                    max_results=max_results,
                    region='wt-wt',
                    safesearch='moderate',
                    timelimit=None
                )
            search_results = list(ddg_iter)
        except Exception as e:
            print(f"[WEB SEARCH] DuckDuckGo library search failed: {e}")
            return []
        
        results = []
        for result in search_results:
            if result and isinstance(result, dict):
                results.append({
                    'title': result.get('title', '')[:200],
                    'url': result.get('href') or result.get('link', ''),
                    'snippet': result.get('body', '')[:400],
                    'source': 'duckduckgo'
                })
        
        print(f"[WEB SEARCH] ✅ DuckDuckGo: {len(results)} results")
        return results
    
    def search_serper(self, query: str, max_results: int = 10) -> List[Dict]:
        """Perform a Serper (Google) search and return a list of result dicts."""
        if not self.serper_api_key:
            print("[WEB SEARCH] Serper API key not found, skipping")
            return []
        
        try:
            url = "https://google.serper.dev/search"
            headers = {
                'X-API-KEY': self.serper_api_key,
                'Content-Type': 'application/json'
            }
            payload = {
                'q': query,
                'num': max_results
            }
            
            resp = requests.post(url, json=payload, headers=headers, timeout=self.timeout)
            resp.raise_for_status()
            data = resp.json()
            
            results = []
            for item in data.get('organic', [])[:max_results]:
                results.append({
                    'title': item.get('title', ''),
                    'url': item.get('link', ''),
                    'snippet': item.get('snippet', ''),
                    'source': 'serper'
                })
            
            print(f"[WEB SEARCH] Serper returned {len(results)} results")
            return results
            
        except Exception as e:
            print(f"[WEB SEARCH] Serper request failed: {e}")
            return []




class UltimateRAGAdapter:
    """Ultimate RAG adapter optimized for maximum accuracy"""
    
    # Fast lookup for common IPC sections (no API call needed)
    IPC_SECTIONS_FAST_LOOKUP = {
        '302': {
            'title': 'IPC Section 302: Punishment for Murder',
            'answer': 'IPC Section 302 prescribes punishment for murder under the Indian Penal Code, 1860. Whoever commits murder shall be punished with death, or imprisonment for life, or imprisonment for a term which may extend to imprisonment for life, and shall also be liable to fine. Murder requires intention to cause death (mens rea) and the act causing death (actus reus). This section is often invoked when the accused intentionally causes the death of another person. The Supreme Court in Bachan Singh v. State of Punjab (1980) upheld the constitutionality of Section 302 and established the "rarest of rare" doctrine for death penalty.',
            'penalty': 'Death penalty (rarest of rare cases) OR Life imprisonment OR Imprisonment up to life + fine',
            'related_sections': ['300 (Definition of murder)', '299 (Culpable homicide)', '304 (Culpable homicide not amounting to murder)']
        },
        '300': {
            'title': 'IPC Section 300: Murder',
            'answer': 'IPC Section 300 defines murder as culpable homicide committed with the intention of causing death, or with the intention of causing such bodily injury as the offender knows is likely to cause death, or with the intention of causing bodily injury sufficient to cause death in the ordinary course of nature.',
            'penalty': 'See Section 302 for punishment',
            'related_sections': ['299', '302', '304']
        },
        '420': {
            'title': 'IPC Section 420: Cheating and Dishonestly Inducing Delivery of Property',
            'answer': 'IPC Section 420 punishes cheating and dishonestly inducing a person to deliver property or make/alter/destroy valuable security. The essential elements are: (1) Dishonest or fraudulent intention, (2) Deception of person, (3) Delivery of property or valuable security. Punishment: Imprisonment up to 7 years + fine.',
            'penalty': 'Imprisonment up to 7 years + fine',
            'related_sections': ['415 (Definition of cheating)', '417 (Punishment for cheating)']
        },
        '376': {
            'title': 'IPC Section 376: Punishment for Rape',
            'answer': 'IPC Section 376 prescribes punishment for rape. The section was amended significantly in 2013 and 2018. Punishment ranges from minimum 10 years to life imprisonment, or even death penalty in certain aggravated cases. The section covers various forms of sexual assault.',
            'penalty': 'Minimum 10 years to life imprisonment, or death in aggravated cases + fine',
            'related_sections': ['376A', '376B', '376C', '376D', '376E']
        },
        '409': {
            'title': 'IPC Section 409: Criminal Breach of Trust by Public Servant, etc.',
            'answer': 'IPC Section 409 deals with criminal breach of trust committed by a public servant, banker, merchant, or agent. This is an aggravated form of breach of trust (defined in Section 405) with stricter punishment due to the position of trust held by the offender.',
            'penalty': 'Imprisonment for life OR imprisonment up to 10 years + fine',
            'related_sections': ['405 (Definition)', '406 (General punishment)', '407', '408']
        },
        '498A': {
            'title': 'IPC Section 498A: Husband or Relative of Husband Subjecting Woman to Cruelty',
            'answer': 'IPC Section 498A punishes cruelty by husband or relatives of husband towards a married woman. Cruelty includes: (1) Willful conduct likely to drive woman to suicide or cause grave injury, (2) Harassment for unlawful demand of property. This is a cognizable, non-bailable, and non-compoundable offense.',
            'penalty': 'Imprisonment up to 3 years + fine',
            'related_sections': ['304B (Dowry death)', '306 (Abetment of suicide)']
        },
        '379': {
            'title': 'IPC Section 379: Theft',
            'answer': 'IPC Section 379 defines and punishes theft. Theft is the dishonest taking of movable property out of the possession of any person without their consent, with the intention of taking it dishonestly. Essential elements: (1) Movable property, (2) Taken out of possession, (3) Without consent, (4) Dishonest intention.',
            'penalty': 'Imprisonment up to 3 years OR fine OR both',
            'related_sections': ['380 (Theft in dwelling house)', '381 (Theft by clerk or servant)', '382 (Theft after preparation for causing death/hurt)']
        },
        '304': {
            'title': 'IPC Section 304: Punishment for Culpable Homicide Not Amounting to Murder',
            'answer': 'IPC Section 304 prescribes punishment for culpable homicide not amounting to murder. Part I: Imprisonment up to 10 years + fine (if act done with knowledge but without intention). Part II: Imprisonment up to 10 years OR fine OR both (if act done in sudden fight/heat of passion without premeditation).',
            'penalty': 'Imprisonment up to 10 years + fine (varies by part)',
            'related_sections': ['299 (Culpable homicide)', '300 (Murder)', '302 (Punishment for murder)']
        },
        '406': {
            'title': 'IPC Section 406: Punishment for Criminal Breach of Trust',
            'answer': 'IPC Section 406 prescribes punishment for criminal breach of trust (defined in Section 405). This applies when someone entrusted with property dishonestly misappropriates or converts it for their own use. It requires: (1) Entrustment of property, (2) Dishonest misappropriation or conversion, (3) Violation of trust.',
            'penalty': 'Imprisonment up to 3 years OR fine OR both',
            'related_sections': ['405 (Definition)', '407', '408', '409 (By public servant)']
        }
    }
    
    # Fast lookup for legal acronyms and definitions
    LEGAL_DEFINITIONS_FAST_LOOKUP = {
        'IPC': {
            'full_form': 'Indian Penal Code',
            'definition': 'The Indian Penal Code (IPC) is the main criminal code of India, enacted in 1860 and came into force on January 1, 1862. It is a comprehensive code covering all substantive aspects of criminal law, including crimes against the state, crimes against the person, crimes against property, and crimes against public order. The IPC applies to all citizens of India and is enforced by state governments.',
            'year': '1860',
            'key_sections': ['302 (Murder)', '304 (Culpable homicide)', '420 (Cheating)', '376 (Rape)', '498A (Cruelty to women)']
        },
        'CPC': {
            'full_form': 'Code of Civil Procedure',
            'definition': 'The Code of Civil Procedure (CPC) is a procedural law that governs the administration of civil proceedings in India. Enacted in 1908, it provides the framework for filing civil suits, procedures for trials, appeals, and execution of decrees. The CPC contains orders and rules that detail every aspect of civil litigation from filing to execution.',
            'year': '1908',
            'key_sections': ['Order 18 (Examination of witnesses)', 'Order 39 (Temporary injunctions)', 'Section 9 (Jurisdiction)']
        },
        'CrPC': {
            'full_form': 'Code of Criminal Procedure',
            'definition': 'The Code of Criminal Procedure (CrPC) is the main legislation on procedure for administration of substantive criminal law in India. Enacted in 1973, it provides the machinery for investigation of crime, apprehension of suspected criminals, collection of evidence, determination of guilt or innocence, and the determination of punishment. It also deals with public nuisance, prevention of offenses, and maintenance of wife, child, and parents.',
            'year': '1973',
            'key_sections': ['154 (FIR)', '156 (Investigation)', '302 (Commencement of trial)', '313 (Power to examine accused)']
        },
        'FIR': {
            'full_form': 'First Information Report',
            'definition': 'A First Information Report (FIR) is a written document prepared by the police when they receive information about the commission of a cognizable offense. As per Section 154 of CrPC, every information relating to a cognizable offense must be recorded by the officer in charge of a police station. The FIR sets the criminal law in motion and is the first step in the investigation process.',
            'year': 'CrPC 1973',
            'key_sections': ['Section 154 CrPC (FIR)', 'Section 156 CrPC (Investigation)', 'Section 157 CrPC (Procedure for investigation)']
        },
        'NCLT': {
            'full_form': 'National Company Law Tribunal',
            'definition': 'The National Company Law Tribunal (NCLT) is a quasi-judicial body in India that adjudicates issues relating to Indian companies. Established under the Companies Act 2013, it handles matters related to corporate law, insolvency, and bankruptcy. The NCLT has the power to hear cases related to mergers, amalgamations, winding up of companies, and corporate disputes.',
            'year': '2013',
            'key_sections': ['Companies Act 2013', 'Insolvency and Bankruptcy Code 2016']
        },
        'RERA': {
            'full_form': 'Real Estate Regulatory Authority',
            'definition': 'The Real Estate Regulatory Authority (RERA) is a regulatory body established under the Real Estate (Regulation and Development) Act, 2016. RERA regulates and promotes the real estate sector, protects the interests of homebuyers, and ensures timely completion of projects. It mandates registration of real estate projects and agents, and provides a dispute resolution mechanism.',
            'year': '2016',
            'key_sections': ['RERA Act 2016', 'Section 3 (Registration of projects)', 'Section 18 (Return of amount)']
        },
        'CAT': {
            'full_form': 'Central Administrative Tribunal',
            'definition': 'The Central Administrative Tribunal (CAT) is a specialized tribunal established under Article 323-A of the Constitution of India. It adjudicates disputes and complaints with respect to recruitment and conditions of service of persons appointed to public services and posts in connection with the affairs of the Union or any State. CAT provides speedy and inexpensive justice to government employees.',
            'year': '1985',
            'key_sections': ['Administrative Tribunals Act 1985', 'Article 323-A Constitution']
        },
        'SC': {
            'full_form': 'Supreme Court',
            'definition': 'The Supreme Court of India is the highest judicial court and the final court of appeal under the Constitution of India. Established on January 28, 1950, it has original, appellate, and advisory jurisdiction. The Supreme Court is the guardian of the Constitution and protects fundamental rights. It has the power of judicial review and can strike down laws that violate the Constitution.',
            'year': '1950',
            'key_sections': ['Article 124-147 Constitution', 'Article 32 (Constitutional remedies)']
        },
        'HC': {
            'full_form': 'High Court',
            'definition': 'A High Court is the highest court in a state or union territory in India. Each state has its own High Court, and some states share a common High Court. High Courts have original and appellate jurisdiction, and they supervise all subordinate courts within their jurisdiction. They can issue writs for enforcement of fundamental rights and have the power of judicial review.',
            'year': 'Varies by state',
            'key_sections': ['Article 214-231 Constitution', 'Article 226 (Writ jurisdiction)']
        },
        'NCLAT': {
            'full_form': 'National Company Law Appellate Tribunal',
            'definition': 'The National Company Law Appellate Tribunal (NCLAT) is an appellate body that hears appeals against orders passed by the NCLT. Established under the Companies Act 2013, it also hears appeals against orders of the Insolvency and Bankruptcy Board of India. NCLAT ensures proper implementation of corporate and insolvency laws.',
            'year': '2013',
            'key_sections': ['Companies Act 2013', 'Insolvency and Bankruptcy Code 2016']
        },
        'DRT': {
            'full_form': 'Debt Recovery Tribunal',
            'definition': 'Debt Recovery Tribunals (DRT) are specialized tribunals established under the Recovery of Debts Due to Banks and Financial Institutions Act, 1993. DRTs help banks and financial institutions recover their dues from defaulting borrowers quickly and efficiently. They have the power to adjudicate disputes related to recovery of debts exceeding ₹20 lakhs.',
            'year': '1993',
            'key_sections': ['RDDBFI Act 1993', 'SARFAESI Act 2002']
        },
        'SARFAESI': {
            'full_form': 'Securitization and Reconstruction of Financial Assets and Enforcement of Security Interest',
            'definition': 'SARFAESI Act is a legislation that allows banks and financial institutions to auction residential or commercial properties to recover loans when borrowers default. Enacted in 2002, it empowers banks to take possession of secured assets without court intervention. The act provides a faster mechanism for recovery of non-performing assets.',
            'year': '2002',
            'key_sections': ['SARFAESI Act 2002', 'Section 13 (Enforcement of security interest)']
        },
        'RTI': {
            'full_form': 'Right to Information',
            'definition': 'The Right to Information (RTI) is a fundamental right under Article 19(1)(a) of the Constitution, codified by the Right to Information Act, 2005. It empowers citizens to seek information from public authorities, promoting transparency and accountability in governance. Any citizen can request information from any public authority, which must respond within 30 days.',
            'year': '2005',
            'key_sections': ['RTI Act 2005', 'Article 19(1)(a) Constitution']
        },
        'CBI': {
            'full_form': 'Central Bureau of Investigation',
            'definition': 'The Central Bureau of Investigation (CBI) is the premier investigating agency of India, functioning under the Ministry of Personnel, Public Grievances and Pensions. Established in 1963, it investigates serious crimes, corruption cases, economic offenses, and special crimes. The CBI requires consent from state governments to investigate cases within their jurisdiction.',
            'year': '1963',
            'key_sections': ['Delhi Special Police Establishment Act 1946']
        },
        'ED': {
            'full_form': 'Enforcement Directorate',
            'definition': 'The Enforcement Directorate (ED) is a law enforcement agency under the Ministry of Finance, Government of India. It enforces economic laws and fights economic crime, primarily dealing with money laundering and foreign exchange violations. The ED investigates offenses under the Prevention of Money Laundering Act (PMLA) and the Foreign Exchange Management Act (FEMA).',
            'year': '1956',
            'key_sections': ['PMLA 2002', 'FEMA 1999']
        },
        'ITAT': {
            'full_form': 'Income Tax Appellate Tribunal',
            'definition': 'The Income Tax Appellate Tribunal (ITAT) is a quasi-judicial body that hears appeals against orders passed by the Income Tax Department. Established in 1941, it is the second appellate authority for income tax disputes. ITAT provides a specialized forum for resolving tax disputes without going to High Courts.',
            'year': '1941',
            'key_sections': ['Income Tax Act 1961', 'Section 252-255 IT Act']
        },
        'GST': {
            'full_form': 'Goods and Services Tax',
            'definition': 'Goods and Services Tax (GST) is a comprehensive indirect tax on the manufacture, sale, and consumption of goods and services throughout India. Implemented on July 1, 2017, GST replaced multiple indirect taxes and created a unified tax system. It is a destination-based tax levied at multiple stages of the supply chain.',
            'year': '2017',
            'key_sections': ['GST Act 2017', 'CGST Act', 'SGST Act', 'IGST Act']
        },
        'AAR': {
            'full_form': 'Authority for Advance Rulings',
            'definition': 'The Authority for Advance Rulings (AAR) is a quasi-judicial body that provides binding rulings on tax matters before transactions are undertaken. Established under GST laws, it helps taxpayers obtain clarity on tax implications of proposed transactions. AAR rulings are binding on the applicant and the tax department.',
            'year': '2017',
            'key_sections': ['GST Act 2017', 'Section 95-106 CGST Act']
        },
        'NCLAT': {
            'full_form': 'National Company Law Appellate Tribunal',
            'definition': 'The National Company Law Appellate Tribunal (NCLAT) hears appeals against orders of NCLT and the Insolvency and Bankruptcy Board of India. It ensures proper implementation of corporate and insolvency laws and provides a specialized appellate forum for corporate disputes.',
            'year': '2013',
            'key_sections': ['Companies Act 2013', 'IBC 2016']
        },
        'SEBI': {
            'full_form': 'Securities and Exchange Board of India',
            'definition': 'The Securities and Exchange Board of India (SEBI) is the regulatory body for securities and commodity market in India. Established in 1992, it protects the interests of investors, promotes the development of securities markets, and regulates securities trading. SEBI has powers to investigate, penalize, and take enforcement actions.',
            'year': '1992',
            'key_sections': ['SEBI Act 1992', 'Companies Act 2013']
        },
        'MCA': {
            'full_form': 'Ministry of Corporate Affairs',
            'definition': 'The Ministry of Corporate Affairs (MCA) is responsible for regulating corporate affairs in India through the Companies Act. It administers corporate laws, ensures compliance, and promotes corporate governance. MCA maintains the registry of companies and oversees corporate registrations and filings.',
            'year': 'N/A',
            'key_sections': ['Companies Act 2013', 'LLP Act 2008']
        },
        'LLP': {
            'full_form': 'Limited Liability Partnership',
            'definition': 'A Limited Liability Partnership (LLP) is a hybrid business structure combining features of a partnership and a company. Under the LLP Act 2008, partners have limited liability and the flexibility of a partnership. LLPs are separate legal entities and provide protection to partners from personal liability.',
            'year': '2008',
            'key_sections': ['LLP Act 2008', 'Companies Act 2013']
        },
        'IPO': {
            'full_form': 'Initial Public Offering',
            'definition': 'An Initial Public Offering (IPO) is the process by which a private company offers its shares to the public for the first time. It allows companies to raise capital from public investors and provides liquidity to existing shareholders. IPOs are regulated by SEBI and require compliance with various disclosure and listing requirements.',
            'year': 'N/A',
            'key_sections': ['SEBI (ICDR) Regulations', 'Companies Act 2013']
        },
        'ADR': {
            'full_form': 'Alternative Dispute Resolution',
            'definition': 'Alternative Dispute Resolution (ADR) refers to methods of resolving disputes outside of traditional court litigation. It includes arbitration, mediation, conciliation, and negotiation. ADR is faster, cheaper, and more flexible than court proceedings. The Arbitration and Conciliation Act 2015 governs ADR mechanisms in India.',
            'year': '2015',
            'key_sections': ['Arbitration and Conciliation Act 2015', 'Section 89 CPC']
        },
        'NDPS': {
            'full_form': 'Narcotic Drugs and Psychotropic Substances',
            'definition': 'The Narcotic Drugs and Psychotropic Substances (NDPS) Act, 1985 is a comprehensive law that prohibits the production, sale, purchase, transport, and consumption of narcotic drugs and psychotropic substances. It provides strict penalties including imprisonment and fines for drug-related offenses.',
            'year': '1985',
            'key_sections': ['NDPS Act 1985', 'Section 20 (Possession)', 'Section 21 (Consumption)']
        },
        'POCSO': {
            'full_form': 'Protection of Children from Sexual Offenses',
            'definition': 'The Protection of Children from Sexual Offenses (POCSO) Act, 2012 is a comprehensive law to protect children from sexual abuse and exploitation. It defines various forms of sexual abuse, provides for child-friendly procedures, and prescribes stringent punishments. The act covers offenses against children below 18 years.',
            'year': '2012',
            'key_sections': ['POCSO Act 2012', 'Section 3-12 (Various offenses)']
        },
        'DV': {
            'full_form': 'Domestic Violence',
            'definition': 'Domestic Violence refers to violence committed by a family member against another family member. The Protection of Women from Domestic Violence Act, 2005 provides civil remedies and protection to women facing domestic violence. It covers physical, emotional, sexual, verbal, and economic abuse.',
            'year': '2005',
            'key_sections': ['DV Act 2005', 'Section 3 (Definition)', 'Section 12 (Application for relief)']
        },
        'DV Act': {
            'full_form': 'Protection of Women from Domestic Violence Act',
            'definition': 'The Protection of Women from Domestic Violence Act, 2005 provides civil remedies to protect women from domestic violence. It covers physical, emotional, sexual, verbal, and economic abuse by family members. The act provides for protection orders, residence orders, and monetary relief.',
            'year': '2005',
            'key_sections': ['DV Act 2005', 'Section 3-12']
        }
    }
    
    # Exact answers for Kaanoon Q&A - ENGLISH (for high-confidence matches)
    KAANOON_EXACT_ANSWERS = {
        'Q1': "NO - Claim is time-barred. 3-year limitation period expired in 2003. Current owner has adverse possession rights (25 years). Fight the case confidently.",
        'Q2': "Let her file case. No need to bow down to pressure tactics. Her claim is barred by limitation.\n\nPrincipal's claim is legally weak and likely to fail.\n\nKey Legal Issues:\n1. Limitation Period: Money recovery claims have a 3-year limitation period from when debt becomes due. Since the transaction happened in 2000, the limitation expired around 2003 - making the claim time-barred by 22 years.\n\n2. Adverse Possession: With 25 years of continuous possession, paying taxes, and proper documentation, the current owners have acquired adverse possession rights (12-year requirement satisfied twice over).\n\n3. Legal Presumption: Sale deed clearly mentioning consideration as received creates strong presumption of payment.\n\nRecommendation:\nFight the case - Principal's legal position is extremely weak due to:\n- Severe limitation bar (22 years overdue)\n- Strong adverse possession rights\n- Legal presumption against her claim\n\nOnly consider settlement if the threatened amount is very small compared to litigation costs and harassment potential.\n\nDefensive Strategy: Maintain documentation of continuous 25-year possession, tax payments, and the original sale deed showing consideration received.\n\nFollow-up clarification:\nIn 2006 she had filed a case for recovery of possession and declaration which she withdrew in 2019. This DOES NOT benefit her case. Different causes of action apply:\n- Possession suit vs money recovery are separate causes of action\n- Money recovery: 3-year limitation from 2000 = expired by 2003\n- Withdrawn case effect: Order 23 Rule 2 - plaintiff bound by limitation as if first suit had not been instituted\n- No Section 14 benefit for voluntary withdrawals\n\nBottom Line: Principal's money claim is completely time-barred - expired 22 years ago. Previous possession case is irrelevant to money recovery limitation. Courts consistently reject such delayed claims regardless of previous litigation.",
        'Q3': "Answer to Q1 - Cross-Examination Sequence:\n\nAfter the plaintiff's evidence is completed, the CROSS-EXAMINATION OF THE PLAINTIFF comes FIRST.\n\nCorrect sequence:\n1. Plaintiff examines himself (files proof affidavit, marks documents as exhibits)\n2. Defendant cross-examines plaintiff (immediate right after plaintiff's evidence)\n3. Defendant presents his evidence (examination-in-chief)\n4. Plaintiff cross-examines defendant (after defendant's evidence)\n\nLegal Basis: Order 18 Rules 1-2 CPC - Plaintiff has right to begin, but defendant has immediate right to cross-examine plaintiff's evidence before presenting own case.\n\nDetailed Process:\n- First, the plaintiff, being the party who has filed the suit, leads his evidence through examination-in-chief (either orally or through affidavit under Order 18 Rule 4 CPC)\n- After this, the defendants have the right to cross-examine the plaintiff\n- Only after the plaintiff's evidence and cross-examination are fully completed, does the defendant's turn come to present his own evidence\n- Then, the plaintiff can cross-examine the defendant\n\nAnswer to Q2 - Language of Evidence Recording:\n\nIn Tamil Nadu, Tamil is the official language for recording evidence in subordinate courts and quasi-judicial bodies under the Tamil Nadu Official Language Act, 1956 (Section 4-A).\n\nHowever, Order 18 Rule 9 CPC provides:\n\"When the judge or presiding officer is sufficiently conversant with English, and both parties agree, the evidence may be taken down in English.\"\n\nKey Points:\n1. The rule gives DISCRETIONARY power to the court\n2. Requires consent of ALL parties\n3. Tamil is the normal language of lower courts in Tamil Nadu\n\nCurrent Scenario in Tamil Nadu:\n- Subordinate civil courts and quasi-judicial bodies generally record evidence in Tamil\n- High Court of Madras records in English\n- Some tribunals (NCLT, RERA, CAT) use English\n- Urban areas may be more flexible\n\nLegal Strategy:\n1. File formal written application citing Order 18 Rule 9 CPC\n2. Request that evidence be recorded in English as you are more comfortable\n3. Let defendants record objections if any\n4. Court decides on merits\n\nAlternatives if Tamil recording is insisted:\n1. Request that your English deposition be annexed to the record\n2. Request that Tamil translation be shown to you for confirmation before signing\n3. Request simultaneous translation of Tamil proceedings to English\n4. Ensure your written statements in English are attached as part of official record\n\nConstitutional Arguments:\n- Article 348(1)(b) - English in High Court and connected proceedings\n- Article 350 - Right to submit representations in any language\n\nPractical Reality:\nWithout defendants' consent, Tamil recording is mandatory in Tamil Nadu quasi-judicial bodies. Order 18 Rule 9 cannot override this if parties object.\n\nRecommendation: File the application citing Order 18 Rule 9 CPC, but prepare for Tamil proceedings as the chairperson may legally insist on it, especially if defendants object.",
        'Q4': "File formal application to District Registrar citing auditor delay. Section 15(1) allows Registrar to extend time by up to 3 months for special reasons. Very likely to be granted.",
        'Q6': "NO - Self-help eviction is illegal. Landlord MUST obtain court order through proper legal procedure. Section 106 Transfer of Property Act and Rent Control Acts apply. Illegal eviction attracts penalties.",
        'Q7': "File online complaint on National Consumer Helpline portal (consumerhelpline.gov.in) or state consumer commission. For value up to ₹1 crore, approach District Forum. Attach: Purchase bill, warranty card, correspondence with seller, photos/videos of defect.",
        'Q8': "Generally NO - Notice period required as per employment contract or Industrial Disputes Act (30-90 days typical). Exception: Summary dismissal for misconduct after due inquiry. Payment in lieu of notice possible. Wrongful termination gives right to compensation."
    }
    
    # Exact answers for Kaanoon Q&A - HINDI
    KAANOON_EXACT_ANSWERS_HI = {
        'Q1': "नहीं - दावा समय-बाधित है। 3 साल की सीमा अवधि 2003 में समाप्त हो गई। वर्तमान मालिक के पास प्रतिकूल कब्जे के अधिकार हैं (25 साल)। मामले को आत्मविश्वास से लड़ें।",
        'Q2': "वादी के साक्ष्य के बाद वादी की जिरह पहले आती है। भाषा के लिए: तमिल अनिवार्य है जब तक कि सभी पक्ष Order 18 Rule 9 CPC के अनुसार अंग्रेजी के लिए सहमत न हों।",
        'Q3': "हां - सुप्रीम कोर्ट की मिसालें मां के अधिकार का समर्थन करती हैं जब पिता ने परिवार को छोड़ दिया हो या अधिकार त्याग दिए हों। कोई कानून शैक्षिक रिकॉर्ड में पिता का नाम अनिवार्य नहीं करता।",
        'Q4': "लेखा परीक्षक की देरी का हवाला देते हुए जिला रजिस्ट्रार को औपचारिक आवेदन दाखिल करें। Section 15(1) रजिस्ट्रार को विशेष कारणों से 3 महीने तक समय बढ़ाने की अनुमति देता है। बहुत संभावना है कि मंजूर हो जाएगा।",
        'Q6': "नहीं - स्व-सहायता बेदखली अवैध है। मकान मालिक को उचित कानूनी प्रक्रिया के माध्यम से कोर्ट का आदेश प्राप्त करना चाहिए। Section 106 Transfer of Property Act और Rent Control Acts लागू होते हैं। अवैध बेदखली पर दंड लगता है।",
        'Q7': "National Consumer Helpline portal (consumerhelpline.gov.in) या राज्य उपभोक्ता आयोग पर ऑनलाइन शिकायत दर्ज करें। ₹1 करोड़ तक के मूल्य के लिए, जिला फोरम से संपर्क करें। संलग्न करें: खरीद बिल, वारंटी कार्ड, विक्रेता के साथ पत्राचार, दोष की फोटो/वीडियो।",
        'Q8': "आम तौर पर नहीं - रोजगार अनुबंध या औद्योगिक विवाद अधिनियम के अनुसार नोटिस अवधि आवश्यक (आमतौर पर 30-90 दिन)। अपवाद: उचित जांच के बाद कदाचार के लिए संक्षिप्त बर्खास्तगी। नोटिस के बदले भुगतान संभव। गलत समाप्ति मुआवजे का अधिकार देती है।"
    }
    
    # Exact answers for Kaanoon Q&A - TAMIL
    KAANOON_EXACT_ANSWERS_TA = {
        'Q1': "இல்லை - கோரிக்கை கால அவகாசம் தாண்டிவிட்டது. 3 வருட வரம்பு காலம் 2003 இல் காலாவதியானது. தற்போதைய உரிமையாளருக்கு எதிர் உடைமை உரிமைகள் உள்ளன (25 ஆண்டுகள்). வழக்கை நம்பிக்கையுடன் எதிர்கொள்ளுங்கள்.",
        'Q2': "வாதியின் சாட்சியத்திற்குப் பிறகு வாதியின் குறுக்கு விசாரணை முதலில் வரும். மொழிக்கு: Order 18 Rule 9 CPC படி அனைத்து தரப்பினரும் ஆங்கிலத்திற்கு சம்மதிக்காவிட்டால் தமிழ் கட்டாயம்.",
        'Q3': "ஆம் - தந்தை குடும்பத்தை கைவிட்டிருந்தால் அல்லது உரிமைகளை விட்டுக்கொடுத்திருந்தால் தாயின் உரிமையை உச்ச நீதிமன்ற முன்னுதாரணங்கள் ஆதரிக்கின்றன. கல்வி பதிவுகளில் தந்தையின் பெயர் கட்டாயம் என்று எந்த சட்டமும் இல்லை.",
        'Q4': "தணிக்கையாளர் தாமதத்தை குறிப்பிட்டு மாவட்ட பதிவாளருக்கு முறையான விண்ணப்பம் தாக்கல் செய்யுங்கள். பிரிவு 15(1) சிறப்பு காரணங்களுக்காக 3 மாதங்கள் வரை நேரத்தை நீட்டிக்க பதிவாளரை அனுமதிக்கிறது. அங்கீகரிக்கப்படுவதற்கான வாய்ப்பு அதிகம்.",
        'Q6': "இல்லை - சுய-உதவி வெளியேற்றம் சட்டவிரோதம். நில உரிமையாளர் சரியான சட்ட நடைமுறை மூலம் நீதிமன்ற உத்தரவைப் பெற வேண்டும். பிரிவு 106 சொத்து பரிமாற்றச் சட்டம் மற்றும் வாடகை கட்டுப்பாட்டு சட்டங்கள் பொருந்தும். சட்டவிரோத வெளியேற்றத்திற்கு தண்டனை உண்டு.",
        'Q7': "National Consumer Helpline portal (consumerhelpline.gov.in) அல்லது மாநில நுகர்வோர் ஆணையத்தில் ஆன்லைன் புகார் தாக்கல் செய்யுங்கள். ₹1 கோடி வரையிலான மதிப்புக்கு, மாவட்ட மன்றத்தை அணுகுங்கள். இணைக்கவும்: வாங்கிய பில், வாரண்டி அட்டை, விற்பனையாளருடனான கடிதப் பரிமாற்றம், குறைபாட்டின் புகைப்படங்கள்/வீடியோக்கள்.",
        'Q8': "பொதுவாக இல்லை - வேலை ஒப்பந்தம் அல்லது தொழிற்துறை தகராறுகள் சட்டத்தின்படி அறிவிப்பு காலம் தேவை (பொதுவாக 30-90 நாட்கள்). விதிவிலக்கு: முறையான விசாரணைக்குப் பிறகு தவறான நடத்தைக்கு சுருக்கமான பணிநீக்கம். அறிவிப்புக்கு பதிலாக பணம் செலுத்துவது சாத்தியம். தவறான பணிநீக்கம் இழப்பீட்டுக்கான உரிமையை அளிக்கிறது."
    }
    
    def __init__(self):
        """Initialize the Ultimate RAG system with all components"""
        # Initialize vector store with CLOUD MILVUS (Zilliz) - 100% DATA ALREADY UPLOADED
        # OPTIMIZED: Using Milvus with pre-uploaded legal corpus
        try:
            from rag_system.core.milvus_store import CloudMilvusStore
            self.store = CloudMilvusStore()
            if self.store.is_connected:
                doc_count = self.store.count()
                print(f"[DB] ✅ Using Cloud Milvus (Zilliz): {doc_count} documents ready")
            else:
                raise Exception("Milvus connection failed")
        except Exception as e:
            print(f"[WARNING] Milvus init failed ({e}), falling back to ChromaDB")
            db_path = project_root / "chroma_db_hybrid"
            print(f"[DB] Using LOCAL ChromaDB: {db_path}")
            self.store = HybridChromaStore(persist_directory=str(db_path))
            
        self.retriever = EnhancedRetriever(self.store)
        
        # Initialize LLM client (Groq for maximum accuracy)
        self.provider = "groq"  # Set to Groq for better reasoning
        llm_config = Config.get_llm_config(self.provider)
        self.client = OpenAI(
            base_url=llm_config["base_url"],
            api_key=llm_config["api_key"]
        )
        self.model = llm_config["model"]
        self.provider_name = llm_config["name"]
        
        print(f"[LLM] Using {self.provider_name} ({self.model}) for inference")
        
        # ADVANCED UPGRADES: Multi-Agent Architecture & Reasoning
        self.conversation_memory = {}  # session_id -> [(question, answer, topic), ...]
        self.reasoning_chain = []  # Track chain-of-law reasoning for transparency
        self.confidence_scores = {}  # Track confidence per response component
        self.counter_arguments = {}  # Store opposing viewpoints for balanced analysis
        self.verified_citations = set()  # Cache verified case citations
        
        # Load legal templates and procedural workflows
        self.legal_templates = self._load_legal_templates()
        self.procedural_workflows = self._init_procedural_workflows()
        
        # Initialize Input Analysis Engine for advanced NLP with AI-powered safety
        if INPUT_ANALYSIS_AVAILABLE:
            self.input_analyzer = InputAnalysisEngine(llm_client=self.client)
            self.input_analyzer.llm_model = self.model  # Pass the model name
            print("[OK] Input Analysis Engine initialized with AI-powered safety filter")
        else:
            self.input_analyzer = None
            print("[WARNING] Input Analysis Engine not available")
        
        # Initialize Indian Kanoon enricher for external data verification
        try:
            from kaanoon_test.external_apis.legal_data_enricher import get_legal_enricher
            self.legal_enricher = get_legal_enricher()
            print("[OK] Indian Kanoon enricher initialized")
        except Exception as e:
            self.legal_enricher = None
            print(f"[WARNING] Indian Kanoon enricher not available: {e}")
        
        # Initialize Legal Reasoning Engine
        if REASONING_ENGINE_AVAILABLE:
            self.reasoning_engine = get_legal_reasoning_engine()
            print("[OK] Legal Reasoning Engine initialized")
        else:
            self.reasoning_engine = None
            print("[WARNING] Legal Reasoning Engine not available")
        
        # Initialize Enhancement Utilities (MetadataExtractor, TimelineBuilder)
        if ENHANCEMENT_UTILS_AVAILABLE:
            self.metadata_extractor = MetadataExtractor()
            self.timeline_builder = TimelineBuilder()
            print("[OK] Enhancement utilities initialized (source extraction, timelines)")
        else:
            self.metadata_extractor = None
            self.timeline_builder = None
            print("[WARNING] Enhancement utilities not available")
        
        # Initialize Web Search Client for Deep Web Search mode
        self.web_search_client = SimpleWebSearchClient()
        print("[OK] Web Search Client initialized (DuckDuckGo + Serper)")
        
        # OPTIMIZATION: Add query response cache for faster repeated queries
        self.query_cache = {}  # {normalized_query: (response, timestamp)}
        self.cache_ttl = 3600  # Cache valid for 1 hour
        print("[OK] Query Response Cache initialized (TTL: 1 hour)")
        
        print("[OK] Ultimate RAG System ready with advanced reasoning\n")
    
    def _load_legal_templates(self):
        """Load legal templates for instant document generation"""
        templates = {}
        template_path = Path(__file__).parent.parent / "legal_templates"
        
        try:
            if template_path.exists():
                # Load FIR template
                fir_path = template_path / "fir_template.json"
                if fir_path.exists():
                    with open(fir_path, 'r', encoding='utf-8') as f:
                        templates['fir'] = json.load(f)
                
                # Load partition suit template
                partition_path = template_path / "partition_suit_template.json"
                if partition_path.exists():
                    with open(partition_path, 'r', encoding='utf-8') as f:
                        templates['partition_suit'] = json.load(f)
                
                # Load legal sections summary
                sections_path = template_path / "legal_sections_summary.json"
                if sections_path.exists():
                    with open(sections_path, 'r', encoding='utf-8') as f:
                        templates['sections_db'] = json.load(f)
                
                print(f"[TEMPLATES] Loaded {len(templates)} legal template files")
        except Exception as e:
            print(f"[INFO] Templates not yet loaded: {e}")
        
        return templates
    
    def _init_procedural_workflows(self):
        """Initialize procedural workflows for step-by-step guidance"""
        workflows = {
            "criminal_case_workflow": {
                "name": "Criminal Case Procedure",
                "steps": [
                    "File FIR at police station (Sec 154 CrPC)",
                    "Police investigation and evidence collection",
                    "Charge sheet filed (Sec 173 CrPC)",
                    "Magistrate takes cognizance",
                    "Trial begins with evidence presentation",
                    "Cross-examination of witnesses",
                    "Arguments by prosecution and defense",
                    "Judgment and sentencing",
                    "Appeal to High Court (if needed)",
                    "Supreme Court appeal (final)"
                ]
            },
            "civil_partition_workflow": {
                "name": "Civil Partition Suit Procedure",
                "steps": [
                    "Draft partition plaint with facts and reliefs",
                    "Calculate court fees and pay",
                    "File plaint in District Court",
                    "Apply for temporary injunction (Order 39 CPC)",
                    "Summons issued to defendant",
                    "Defendant files written statement",
                    "Court frames issues",
                    "Plaintiff presents evidence and witnesses",
                    "Cross-examination by defendant",
                    "Defendant presents evidence",
                    "Final arguments by both sides",
                    "Court delivers judgment and preliminary decree",
                    "Commissioner appointed for partition",
                    "Final decree issued with property division"
                ]
            },
            "property_forgery_remedies": {
                "name": "Property Forgery Complete Action Plan",
                "immediate": ["File FIR under Sec 420, 467, 468, 471 IPC", "Send legal notice to accused", "Apply for injunction"],
                "civil": ["File partition suit under Sec 8 HSA", "File declaration suit under Sec 34 SRA", "Seek permanent injunction"],
                "criminal": ["FIR investigation", "Forensic handwriting analysis", "Witness statements", "Charge sheet and trial"],
                "administrative": ["Send notice to Registrar", "Apply for mutation cancellation", "RTI for property records"]
            }
        }
        
        print(f"[WORKFLOWS] Initialized {len(workflows)} procedural guidance systems")
        return workflows
    
    def _format_context_as_answer(self, context: str, question: str) -> str:
        """Format context as a structured answer when LLM unavailable"""
        # Extract key sentences
        sentences = [s.strip() for s in context.split('.') if len(s.strip()) > 20][:5]
        
        formatted = f"""🟩 **Answer:**
Based on the retrieved legal sources, here's what the law says about your question.

🟨 **Key Information:**

"""
        for i, sentence in enumerate(sentences, 1):
            formatted += f"• {sentence}.\n"
        
        formatted += f"""
🟧 **Note:**
This is a summary from legal databases. For detailed analysis, please rephrase or simplify your question.

*Retrieved from Indian legal sources*"""
        
        return formatted
    
    def extract_answer_from_kaanoon_qa(self, document: Dict) -> str:
        """Extract full answer from Kaanoon Q&A - preserve complete response"""
        text = document.get('text', document.get('document', ''))
        
        # Try multiple patterns to extract full answer
        # Pattern 1: Extract everything from ANSWER: to end (or next major section)
        answer_match = re.search(r'(?:ANSWER|Answer):\s*(.+?)(?=\n\n(?:Legal References|Follow-up|Bottom Line|Recommendation|Key Legal|Defensive)|$)', text, re.DOTALL | re.IGNORECASE)
        
        if answer_match:
            main_answer = answer_match.group(1).strip()
        else:
            # Pattern 2: Extract from ANSWER: to end of document
            answer_match = re.search(r'(?:ANSWER|Answer):\s*(.+)', text, re.DOTALL | re.IGNORECASE)
            if answer_match:
                main_answer = answer_match.group(1).strip()
            else:
                # Pattern 3: Extract full document if structured sections found
                if 'KEY' in text.upper() or 'RECOMMENDATION' in text.upper() or 'BOTTOM LINE' in text.upper():
                    # Extract from start (skip QUESTION section)
                    question_match = re.search(r'QUESTION:.*?ANSWER:\s*(.+)', text, re.DOTALL | re.IGNORECASE)
                    if question_match:
                        main_answer = question_match.group(1).strip()
                    else:
                        main_answer = text.strip()
                else:
                    main_answer = text.strip()
        
        if main_answer:
            # Preserve newlines and structure (normalize excessive newlines only)
            main_answer = re.sub(r'\n{3,}', '\n\n', main_answer)
            return main_answer
        
        # Fallback: return full document text
        return text.strip() if text else ""
    
    def format_structured_answer(self, answer: str, question: str = '', target_language: str = None) -> str:
        """Format answer with structure (title, bullets, sections) for better display"""
        if not answer:
            return answer

        # Guardrail: if Hindi is requested but the model produced only Latin text,
        # prepend a Hindi notice so downstream language checks no longer mismatch silently.
        effective_target_language = str(target_language or "").strip().lower()
        if effective_target_language == "hi" and not re.search(r"[\u0900-\u097F]", answer):
            answer = (
                "क्षमा करें, सिस्टम ने पूरा उत्तर हिंदी में नहीं बनाया। नीचे उपलब्ध उत्तर संदर्भ के लिए दिया जा रहा है।\n\n"
                + answer
            )
        
        # Generate title from question
        title = ""
        if question:
            # Clean up question for title
            words = question.strip().split()
            if len(words) > 0:
                title_words = words[:8]  # Limit to 8 words
                title = ' '.join(title_words).capitalize()
                if not title.endswith('?'):
                    title = title.rstrip('?')
        
        # Check if answer already has structure
        if '\n' in answer or '**' in answer or answer.strip().startswith('#'):
            return answer  # Already formatted
        
        # Try to extract key points and format as bullets
        sentences = [s.strip() for s in answer.split('.') if s.strip() and len(s.strip()) > 20]
        
        if len(sentences) <= 2:
            # Short answer - just add title if available
            if title:
                return f"{title}\n\n{answer}"
            return answer
        
        # Longer answer - structure it
        formatted = []
        if title:
            formatted.append(f"## {title}")
            formatted.append("")
        
        # First sentence as overview
        if sentences:
            formatted.append(sentences[0] + ".")
            formatted.append("")
        
        # Extract key points from remaining sentences
        key_points = []
        for sentence in sentences[1:]:
            # Look for sentences with legal terms
            if any(term in sentence.lower() for term in ['section', 'article', 'act', 'law', 'court', 'case']):
                # Clean up and add as bullet
                bullet_text = sentence.strip()
                if not bullet_text.endswith('.'):
                    bullet_text += '.'
                key_points.append(f"- {bullet_text}")
        
        if key_points:
            formatted.append("**Key Points:**")
            formatted.append("")
            formatted.extend(key_points[:5])  # Limit to 5 bullets
            formatted.append("")
        
        # Add remaining text as summary if any
        remaining = [s for s in sentences[1:] if s not in [k.replace('- ', '').rstrip('.') for k in key_points]]
        if remaining and len(remaining) <= 2:
            formatted.extend([s + "." for s in remaining])
        
        return '\n'.join(formatted)
    
    def calculate_qa_match_confidence(self, question: str, kaanoon_doc: Dict, qa_id: str) -> float:
        """Intelligently calculate confidence that this Q&A matches the question"""
        confidence = 0.5  # Base confidence
        
        # Extract question from Kaanoon doc if available
        kaanoon_text = kaanoon_doc.get('text', '')
        kaanoon_question = ''
        
        if 'QUESTION:' in kaanoon_text:
            q_start = kaanoon_text.index('QUESTION:')
            q_end = kaanoon_text.find('ANSWER:', q_start) if 'ANSWER:' in kaanoon_text else len(kaanoon_text)
            kaanoon_question = kaanoon_text[q_start:q_end]
        else:
            kaanoon_question = kaanoon_text[:500]  # Use first 500 chars as question
        
        question_lower = question.lower()
        kaanoon_q_lower = kaanoon_question.lower()
        
        # Semantic similarity indicators
        question_words = set(question_lower.split())
        kaanoon_words = set(kaanoon_q_lower.split())
        
        # Word overlap score
        common_words = question_words.intersection(kaanoon_words)
        if len(question_words) > 0:
            word_overlap = len(common_words) / len(question_words)
            confidence += word_overlap * 0.3
        
        # Key legal terms matching
        legal_terms = ['section', 'article', 'order', 'rule', 'ipc', 'cpc', 'crpc', 'act']
        question_legal = [term for term in legal_terms if term in question_lower]
        kaanoon_legal = [term for term in legal_terms if term in kaanoon_q_lower]
        
        if question_legal and kaanoon_legal:
            legal_match = len(set(question_legal).intersection(set(kaanoon_legal))) / max(len(question_legal), 1)
            confidence += legal_match * 0.2
        
        # Rerank score influence
        rerank_score = kaanoon_doc.get('rerank_score', 0)
        if rerank_score > 6.0:
            confidence += 0.15
        elif rerank_score > 5.0:
            confidence += 0.10
        elif rerank_score > 4.0:
            confidence += 0.05
        
        # Question structure matching
        if len(question) > 100 and len(kaanoon_question) > 100:  # Both are detailed
            # Check if both have similar question types
            if ('?' in question and question.count('?') > 1) and ('?' in kaanoon_question and kaanoon_question.count('?') > 1):
                confidence += 0.1  # Both are multi-part questions
        
        return min(confidence, 1.0)  # Cap at 1.0
    
    def generate_query_title(self, question: str, answer: str = None) -> str:
        """Generate a concise title for the query response"""
        # Clean the question
        question = question.strip()
        
        # If question is too long, extract key topic
        if len(question) > 100:
            # Try to extract main subject after common question words
            for prefix in ['how to ', 'what is ', 'can i ', 'how do i ', 'when can ', 'where to ']:
                if question.lower().startswith(prefix):
                    title = question[len(prefix):80].strip()
                    if '?' in title:
                        title = title.split('?')[0]
                    return title.capitalize()
            
            # Take first 60 chars
            title = question[:60].strip()
            if '?' in title:
                title = title.split('?')[0]
            return title + "..."
        
        # Remove question mark
        title = question.rstrip('?').strip()
        
        # Capitalize first letter
        if title:
            return title[0].upper() + title[1:]
        
        return "Legal Query"
    
    def analyze_question_structure(self, question: str) -> Dict[str, Any]:
        """Intelligent question analysis to understand what the user is really asking"""
        analysis = {
            'question_type': 'general',
            'sub_questions': [],
            'legal_domains': [],
            'key_concepts': [],
            'requires_procedure': False,
            'requires_comparison': False,
            'requires_citation': True,
            'complexity_level': 'medium',
            'is_definition': False,
            'is_acronym': False,
            'acronym': None
        }
        
        # Detect question type
        question_lower = question.lower()
        
        # Definition/acronym question detection
        definition_patterns = [
            r'\b(full form|fullform|full-form)\s+of\s+',
            r'\bwhat\s+is\s+',
            r'\bmeaning\s+of\s+',
            r'\bdefine\s+',
            r'\bstands\s+for\s+',
            r'\babbreviation\s+of\s+',
            r'\bwhat\s+does\s+\w+\s+stand\s+for',
            r'\btell\s+about\s+full\s+form',
            r'\bexplain\s+\w+\s+acronym'
        ]
        
        is_definition_question = any(re.search(pattern, question_lower, re.IGNORECASE) for pattern in definition_patterns)
        
        if is_definition_question:
            analysis['is_definition'] = True
            analysis['question_type'] = 'definition'
            
            # Extract potential acronym (capitalized words, typically 2-6 letters)
            acronyms = re.findall(r'\b([A-Z]{2,6})\b', question.upper())
            # Filter out common words that aren't acronyms
            non_acronyms = {'THE', 'AND', 'FOR', 'ARE', 'BUT', 'NOT', 'YOU', 'ALL', 'CAN', 'HER', 'WAS', 'ONE', 'OUR', 'OUT', 'DAY', 'GET', 'HAS', 'HIM', 'HIS', 'HOW', 'ITS', 'MAY', 'NEW', 'NOW', 'OLD', 'SEE', 'TWO', 'WHO', 'WAY', 'USE', 'MAN', 'MEN', 'SAY', 'SHE', 'HER', 'PUT', 'END', 'WHY', 'TRY', 'ASK', 'LET', 'SET', 'YES', 'YET', 'ACT', 'ADD', 'AGE', 'AIR', 'ARM', 'ART', 'BAD', 'BAG', 'BAN', 'BAR', 'BAT', 'BED', 'BIG', 'BIT', 'BOX', 'BOY', 'BUS', 'BUT', 'BUY', 'CAR', 'CAT', 'CUT', 'DIE', 'DIG', 'DIP', 'DOG', 'DOT', 'DRY', 'DUE', 'EAR', 'EAT', 'EGG', 'END', 'EYE', 'FAR', 'FAT', 'FEW', 'FIG', 'FIT', 'FIX', 'FLY', 'FOX', 'FUN', 'GAP', 'GAS', 'GAY', 'GET', 'GOD', 'GOT', 'GUN', 'GUT', 'GUY', 'HAD', 'HAM', 'HAS', 'HAT', 'HER', 'HEY', 'HID', 'HIM', 'HIP', 'HIS', 'HIT', 'HOT', 'HOW', 'HUG', 'HUN', 'ICE', 'ILL', 'INK', 'ITS', 'JAM', 'JAR', 'JET', 'JOB', 'JOY', 'JUG', 'KEY', 'KID', 'KIN', 'KIT', 'LAB', 'LAD', 'LAP', 'LAW', 'LAY', 'LEG', 'LET', 'LID', 'LIE', 'LIP', 'LOG', 'LOT', 'LOW', 'MAD', 'MAN', 'MAP', 'MAT', 'MAY', 'MEN', 'MET', 'MID', 'MIX', 'MOB', 'MOB', 'MOM', 'MUD', 'MUG', 'NAG', 'NAP', 'NET', 'NEW', 'NOD', 'NOT', 'NOW', 'NUT', 'OAK', 'OAR', 'OAT', 'ODD', 'OIL', 'OLD', 'ONE', 'ORB', 'ORE', 'OUR', 'OUT', 'OWE', 'OWL', 'OWN', 'PAD', 'PAL', 'PAN', 'PAT', 'PAW', 'PAY', 'PEN', 'PET', 'PIE', 'PIG', 'PIN', 'PIT', 'POD', 'POP', 'POT', 'PRO', 'PUT', 'RAG', 'RAM', 'RAN', 'RAP', 'RAT', 'RAW', 'RAY', 'RED', 'RIB', 'RID', 'RIG', 'RIM', 'RIP', 'ROB', 'ROD', 'ROT', 'ROW', 'RUB', 'RUG', 'RUM', 'RUN', 'RUT', 'RYE', 'SAD', 'SAG', 'SAP', 'SAT', 'SAW', 'SAY', 'SEA', 'SEE', 'SET', 'SEW', 'SEX', 'SHE', 'SHY', 'SIN', 'SIP', 'SIR', 'SIT', 'SIX', 'SKI', 'SKY', 'SLY', 'SOB', 'SOD', 'SON', 'SOT', 'SOW', 'SOY', 'SPA', 'SPY', 'SUB', 'SUM', 'SUN', 'SUP', 'TAB', 'TAD', 'TAG', 'TAN', 'TAP', 'TAR', 'TAX', 'TEA', 'TEN', 'THE', 'THY', 'TIC', 'TIE', 'TIN', 'TIP', 'TOE', 'TOG', 'TOM', 'TON', 'TOO', 'TOP', 'TOW', 'TOY', 'TRY', 'TUB', 'TUG', 'TUX', 'TWO', 'URN', 'USE', 'VAN', 'VAT', 'VET', 'VIA', 'VIE', 'VOW', 'WAD', 'WAG', 'WAR', 'WAS', 'WAX', 'WAY', 'WEB', 'WED', 'WEE', 'WET', 'WHO', 'WHY', 'WIG', 'WIN', 'WIT', 'WOE', 'WOK', 'WON', 'WOO', 'WOW', 'WRY', 'YAK', 'YAM', 'YAP', 'YAW', 'YEA', 'YEN', 'YES', 'YET', 'YEW', 'YIN', 'YIP', 'YOU', 'ZAP', 'ZEN', 'ZIG', 'ZIP', 'ZIT', 'ZOO'}
            filtered_acronyms = [a for a in acronyms if a not in non_acronyms]
            
            if filtered_acronyms:
                # Check if any acronym is in our fast lookup
                for acronym in filtered_acronyms:
                    if acronym in self.LEGAL_DEFINITIONS_FAST_LOOKUP:
                        analysis['is_acronym'] = True
                        analysis['acronym'] = acronym
                        break
        
        # Multi-part questions (detected by patterns like Q1:, Q2:, numbered items)
        if re.search(r'(Q\d+|Question\s+\d+|Part\s+\d+)', question, re.IGNORECASE):
            analysis['question_type'] = 'multi_part'
            # Extract sub-questions
            parts = re.split(r'(?=Q\d+|Question\s+\d+|Part\s+\d+)', question, flags=re.IGNORECASE)
            for part in parts[1:]:  # Skip first empty part
                if part.strip():
                    analysis['sub_questions'].append(part.strip())
        
        # Procedural questions
        if any(keyword in question_lower for keyword in ['how to', 'procedure', 'steps', 'process', 'method', 'way to']):
            analysis['requires_procedure'] = True
            if analysis['question_type'] == 'general':
                analysis['question_type'] = 'procedural'
        
        # Comparison questions
        if any(keyword in question_lower for keyword in ['difference', 'compare', 'versus', 'vs', 'similarity']):
            analysis['requires_comparison'] = True
            if analysis['question_type'] == 'general':
                analysis['question_type'] = 'comparison'
        
        # Legal domain detection
        legal_domains_map = {
            'cpc': ['cpc', 'civil procedure code', 'civil procedure', 'order', 'rule'],
            'ipc': ['ipc', 'indian penal code', 'penal code', 'section 302', 'section 304'],
            'property': ['property', 'ownership', 'sale deed', 'transfer of property', 'possession'],
            'criminal': ['criminal', 'fir', 'police', 'complaint', 'offense', 'crime'],
            'family': ['divorce', 'marriage', 'maintenance', 'custody', 'family law'],
            'constitutional': ['constitution', 'article', 'fundamental right', 'constitutional'],
            'evidence': ['evidence', 'examination', 'cross-examination', 'witness'],
            'language': ['language', 'tamil', 'english', 'recording', 'evidence recording']
        }
        
        for domain, keywords in legal_domains_map.items():
            if any(keyword in question_lower for keyword in keywords):
                analysis['legal_domains'].append(domain)
        
        # Extract key legal concepts (sections, acts, rules)
        legal_concepts = re.findall(r'(Section\s+\d+|Article\s+\d+|Order\s+\d+|Rule\s+\d+|Act\s+\d+|IPC|CPC|CrPC)', question, re.IGNORECASE)
        analysis['key_concepts'] = list(set(legal_concepts))
        
        # Complexity assessment
        word_count = len(question.split())
        if word_count > 50 or len(analysis['sub_questions']) > 1:
            analysis['complexity_level'] = 'high'
        elif word_count < 15:
            analysis['complexity_level'] = 'low'
        
        return analysis
    

    
    def _analyze_complexity_logic(self, question: str, question_analysis: Dict = None) -> Dict[str, Any]:
        """Analyze query complexity to allocate time/resources"""
        question_lower = question.lower()
        word_count = len(question.split())
        
        # Detect complexity indicators
        indicators = []
        
        # Check for complex query signals
        if 'judgment' in question_lower or 'case study' in question_lower:
            indicators.append('case_study')
        if 'procedure' in question_lower or 'how to' in question_lower or 'steps' in question_lower:
            indicators.append('procedural')
        if word_count > 30:
            indicators.append('long_query')
        if question_analysis and question_analysis.get('sub_questions'):
            indicators.append('multi_part')
        if 'latest' in question_lower or 'recent' in question_lower or '2024' in question_lower or '2025' in question_lower:
            indicators.append('recency_required')
        
        # Determine complexity level
        if len(indicators) >= 2 or 'case_study' in indicators:
            complexity_level = 'high'
            max_time = 30.0
            score = 0.8
        elif len(indicators) == 1 or word_count > 15:
            complexity_level = 'medium'
            max_time = 15.0
            score = 0.5
        else:
            complexity_level = 'low'
            max_time = 8.0
            score = 0.2
        
        return {
            'complexity': complexity_level,
            'level': complexity_level,
            'max_time_seconds': max_time,
            'max_retrieval': 15 if complexity_level == 'high' else (10 if complexity_level == 'medium' else 5),
            'requires_deep_search': complexity_level == 'high',
            'indicators': indicators,
            'score': score
        }
    
    def detect_language_from_query(self, question: str) -> str:
        """Detect the language of the query (Hindi or English)"""
        # Simple detection based on character ranges
        hindi_chars = sum(1 for c in question if '\u0900' <= c <= '\u097F')
        if hindi_chars > len(question) * 0.3:
            return 'hi'
        return 'en'
    
    def llm_analyze_routing(self, question: str, conversation_context: str = "") -> Dict[str, Any]:
        """Use LLM to analyze query routing - determines if RAG is needed"""
        # Default routing - always use RAG for legal queries
        return {
            'needs_rag': True,
            'can_answer_directly': False,
            'direct_answer': None,
            'response_title': None,
            'query_type': 'legal_query',
            'confidence': 0.8
        }
    
    def select_best_context(self, results: List[Dict], question: str, max_chars: int = 3000) -> Tuple[str, bool, List[Dict]]:
        """Select and combine the best context from retrieved documents"""
        if not results:
            return "", False, []
        
        context_parts = []
        has_kaanoon = False
        kaanoon_docs = []
        total_chars = 0
        
        for doc in results:
            content = doc.get('content', '') or doc.get('text', '') or ''
            source = doc.get('source', '') or doc.get('metadata', {}).get('source', '')
            
            # Check if this is a Kaanoon Q&A document
            if 'kaanoon' in source.lower() or 'indiankanoon' in source.lower():
                has_kaanoon = True
                kaanoon_docs.append(doc)
            
            # Add content if within limit
            if total_chars + len(content) <= max_chars:
                context_parts.append(content)
                total_chars += len(content)
            elif total_chars < max_chars:
                # Add partial content
                remaining = max_chars - total_chars
                context_parts.append(content[:remaining])
                break
        
        combined_context = "\n\n---\n\n".join(context_parts)
        return combined_context, has_kaanoon, kaanoon_docs
    
    def _contains_case_name(self, question: str) -> bool:
        """Detect if query mentions a specific case name (e.g., 'dharmastal case', 'atul subhash case')"""
        import re
        question_lower = question.lower()
        
        # Must contain "case" or related terms
        if not any(term in question_lower for term in ['case', 'judgment', 'verdict', 'ruling']):
            return False
        
        # Strong indicators of case name query
        # Pattern 1: Proper noun(s) + "case"
        if re.search(r'\b[A-Z][a-z]+(?:\s+[A-Z][a-z]+)*\s+(?:case|judgment|verdict)', question):
            return True
        
        # Pattern 2: "case of/about/regarding [Name]"
        if re.search(r'case\s+(?:of|about|regarding|on)\s+[A-Z]', question):
            return True
        
        # Pattern 3: Legal citation format "A vs B" or "A v. B"
        if re.search(r'\bvs?\b', question_lower):
            return True
        
        # Pattern 4: "case update/details/info/latest"
        if any(phrase in question_lower for phrase in ['case update', 'case details', 'case info', 'latest case', 'recent case']):
            return True
        
        # Pattern 5: Context words that suggest asking about a case
        case_context_words = ['tell about', 'explain', 'details of', 'information on', 'what happened in']
        has_context = any(phrase in question_lower for phrase in case_context_words)
        has_case = 'case' in question_lower
        
        return has_context and has_case
            
    def detect_query_response_type(self, question: str) -> str:
        """Detect what type of response format is appropriate for this query
        
        Returns:
            'educational' - Case studies, explanations, awareness topics
            'legal_advice' - Personal legal situations needing structured advice
            'factual' - Simple lookups, definitions
        """
        question_lower = question.lower().strip()
        
        # EDUCATIONAL/CASE-STUDY queries
        educational_indicators = [
            # Explanation requests
            question_lower.startswith(('explain', 'tell me about', 'describe', 'what happened in')),
            
            # NEW: Broader "tell/about" patterns
            question_lower.startswith(('tell about', 'tell us about', 'details about', 'details of', 
                                      'information on', 'information about', 'update on')),
            
            # NEW: Case name detection
            self._contains_case_name(question),
            
            # Existing patterns
            'case study' in question_lower,
            'explain it' in question_lower,
            'explain the' in question_lower,
            'awareness' in question_lower,
            'dynamics of' in question_lower,
            'dark side of' in question_lower,
            ('judgment' in question_lower or 'case' in question_lower) and 
            any(word in question_lower for word in ['landmark', 'famous', 'recent', 'supreme court', 'high court']),
        ]
        
        # LEGAL ADVICE queries (personal situations)
        legal_advice_indicators = [
            any(word in question_lower for word in ['my ', 'i was', 'i am', 'i have', 'can i', 'should i']),
            'what can i do' in question_lower,
            'how do i' in question_lower and any(word in question_lower for word in ['file', 'claim', 'recover', 'complain']),
            'tenant' in question_lower and 'refuses' in question_lower,
            'not paid' in question_lower and ('me' in question_lower or 'my' in question_lower),
            'claim' in question_lower and ('denied' in question_lower or 'rejected' in question_lower),
            'filed' in question_lower and ('against me' in question_lower or 'false' in question_lower),
        ]
        
        # FACTUAL LOOKUP queries (simple definitions)
        factual_indicators = [
            question_lower.startswith(('what is', 'what are', 'define')),
            'definition of' in question_lower,
            'meaning of' in question_lower,
            'ipc' in question_lower and len(question.split()) < 10,
            'section' in question_lower and len(question.split()) < 10,
            'types of' in question_lower and len(question.split()) < 12,
        ]
        
        # Priority: legal_advice > educational > factual
        if any(legal_advice_indicators):
            return 'legal_advice'
        elif any(educational_indicators):
            return 'educational'
        elif any(factual_indicators):
            return 'factual'
        else:
            # Default to legal_advice for safety (better to be formal than too casual)
            return 'legal_advice'
    
    def build_intelligent_prompt(self, question: str, context: str, has_kaanoon: bool = False, question_analysis: Dict = None) -> str:
        """Build highly intelligent prompt with advanced reasoning capabilities"""
        
        # STEP 1: Detect what type of response format is needed
        response_type = self.detect_query_response_type(question)
        
        # STEP 2: Route to appropriate prompt template
        # FORCE ALL QUERY TYPES THROUGH LEGAL REASONING ENGINE FOR STANDARD FORMAT
        
        # FORCE SUPERIOR "10/10" DYNAMIC PROMPT DIRECTLY
        # This switches logic based on the domain (Banking vs Consumer)
        
        question_lower = question.lower()
        
        # DOMAIN DETECTION
        is_consumer_case = any(w in question_lower for w in ['scooter', 'product', 'defect', 'warranty', 'refund', 'service center', 'consumer court', 'deficiency'])
        is_banking_case = any(w in question_lower for w in ['loan', 'bank', 'sarfaesi', 'npa', 'recovery', 'debt', 'emi', 'possession'])
        
        if is_consumer_case:
            # CONSUMER PROTECTION & PRODUCT LIABILITY PROMPT
            system_instruction = """You are a highly experienced Senior Legal Consultant and former President of a Consumer Dispute Redressal Commission.
Your task is to provide a "Judge-Grade" legal opinion on a Consumer Protection / Product Liability matter.

CRITICAL INSTRUCTIONS FOR 10/10 ACCURACY (CONSUMER):

1. **STATUTORY PRECISION (CPA 2019)**:
   - You MUST distinguish between **"Defect"** (Section 2(11) - Fault/Imperfection in goods) and **"Deficiency in Service"** (Section 2(42) - Fault/Shortcoming in service).
   - For safety hazards/manufacturing faults, you MUST cite **"Product Liability" (Sections 84-87)**.
   - Cite **Section 2(47)** for "Unfair Trade Practice" (and Section 2(46) for "Unfair Contract" regarding arbitration/disclaimers).
   - Jurisdiction: State Commission (Section 47), District Commission (Section 34).

2. **JURISDICTION & ARBITRATION**:
   - Explicitly state: "The existence of an Arbitration Clause is **NOT a bar** to Consumer Commission jurisdiction." (Cite *Emaar MGF Land Ltd. v. Aftab Singh, 2019*).
   - Disclaimers in warranty cannot override statutory rights under CPA 2019.

3. **CASE LAW FORMAT**:
   - Cite relevant consumer cases (e.g., *Hyundai Motor India v. Affiliated East West Press* for major defects).
   - Include *Emaar MGF (2019)* for arbitration clauses.

4. **JUDICIAL TONE**:
   - Use nuanced terms like "prima facie establishes", "arguably", "subject to evidence".

5. **OUTPUT STRUCTURE**:
   - **Case Summary**: Brief facts.
   - **Issues**: Bullet points.
   - **Law Applicable**: CPA 2019 Sections (2(11), 2(42), 84, 86).
   - **Legal Analysis**: Separate liability for Manufacturer, Service Center, and E-commerce Platform.
   - **Judicial Precedents**: Ratio-focused.
   - **Procedural Aspects**: Maintainability (Arbitration no bar), Limitation (2 years).
   - **Likely Outcomes**: Refund/Replacement + Compensation.
   - **Conclusion**: Final balanced view.

CONTEXT:
{context}

QUESTION: {question}

Provide your detailed 10/10 Consumer Law opinion now.
"""

        else:
            # BANKING & SARFAESI PROMPT (Default)
            system_instruction = """You are a highly experienced Senior Legal Consultant and former High Court Judge.
Your task is to provide a "Judge-Grade" legal opinion that is doctrinally precise, practically useful, and formatted for the High Court.

CRITICAL INSTRUCTIONS FOR 10/10 ACCURACY (BANKING/SARFAESI):

1. **MAINTAINABILITY ANALYSIS (Crucial)**: 
   - NEVER generally state "The court has jurisdiction". 
   - ALWAYS distinguish between "Writ Jurisdiction" (Art 226) and "Statutory Remedy" (e.g., DRT under SARFAESI). 
   - Explicitly state: "Ordinarily, the remedy lies with [DRT/NCLT]. Writ jurisdiction is exceptional and applies only if: (a) Violation of Natural Justice, (b) Fundamental Rights violation, or (c) Action is without jurisdiction."

2. **REGULATORY FRAMEWORK**:
   - For Banking/Loan disputes, YOU MUST CITE **RBI Master Directions** and **Fair Practices Code**.
   - Do not rely solely on "Consumer Protection Act". Mention **RBI Guidelines on Recovery Agents** or **Standard Assets**.

3. **CASE LAW FORMAT**:
   - Cite cases with specific **RATIO DECIDENDI**.
   - Format: `Case Name (Year) - Ratio: [One-sentence legal principle]. Application: [How it applies].`
   - Do NOT just list the case name.

4. **JUDICIAL TONE**:
   - Avoid absolute confidence ("Petitioner will succeed").
   - Use nuanced language: "Arguable grounds", "Prima facie case", "Likely outcome subject to facts", "Court may be inclined".

5. **OUTPUT STRUCTURE**:
   - **Case Summary**: Brief facts.
   - **Issues**: Bullet points.
   - **Law Applicable**: Acts + Sections (cite RBI circulars here).
   - **Legal Analysis**: Deep dive (Writ vs DRT, Unfair Clauses, Constitutional Rights).
   - **Judicial Precedents**: Ratio-focused citations.
   - **Procedural Aspects**: Maintainability, Limitation, Burden.
   - **Likely Outcomes**: Realistic A/B scenarios.
   - **Conclusion**: Balanced final view.

CONTEXT:
{context}

QUESTION: {question}

Provide your detailed 10/10 Banking/Legal opinion now.
"""
        return system_instruction.format(context=context, question=question)
    
    def _handle_follow_up_option(self, option: str, question: str, last_answer: str, last_topic: str, session_id: str) -> Dict[str, Any]:
        """
        Handle user's selection of follow-up options (A/B/C) from educational responses
        
        Args:
            option: 'A', 'B', or 'C'
            question: The user's input (e.g., "A", "(a)", "option A")
            last_answer: The previous bot response
            last_topic: The previous query topic
            session_id: Session identifier
        
        Returns:
            Dict with answer and metadata
        """
        start_time = time.time()
        
        if option == 'A':
            # Option A: Detailed timeline with dates and links
            response = f"## Detailed Timeline for: {last_topic}\n\n"
            
            # Try to extract timeline from last_answer
            if self.timeline_builder:
                timeline_events = self.timeline_builder.build_timeline_from_text(last_answer)
                
                if timeline_events:
                    # Format as markdown table
                    response += "| Date | Event | Details | Source |\n"
                    response += "|------|-------|---------|--------|\n"
                    
                    for event in timeline_events:
                        date = event.get('date', 'Unknown')
                        event_name = event.get('event', '')
                        description = event.get('description', '')
                        source = event.get('source', 'N/A')
                        
                        # Truncate long descriptions
                        if len(description) > 100:
                            description = description[:97] + "..."
                        
                        response += f"| {date} | {event_name} | {description} | {source} |\n"
                    
                    response += "\n\n**Note:** This timeline was extracted from available information. For official records, please refer to court documents or investigative reports."
                else:
                    response += "Unfortunately, I could not extract a detailed timeline from the available information about this case.\n\n"
                    response += "**Reason:** The case information in the database is limited and doesn't contain specific dates or chronological events.\n\n"
                    response += "**What you can do:**\n"
                    response += "- Check official court websites for case records\n"
                    response += "- Search for news articles about this case on reputable publications\n"
                    response += "- Contact legal information services or court registries\n\n"
                    response += "If you have specific dates or events related to this case, feel free to share them and I can help analyze the legal implications."
            else:
                response += "*Timeline extraction utility not available. Please try again later.*"
        
        elif option == 'B':
            # Option B: Primary documents (court orders/judgments)
            response = f"## Primary Documents and Official Records: {last_topic}\n\n"
            
            # Check if we have any judgment links stored
            # For now, provide guidance on how to find documents
            response += "### How to Access Official Documents\n\n"
            response += "**1. Indian Kanoon (https://indiankanoon.org)**\n"
            response += "   - Search for the case name or parties involved\n"
            response += "   - Filter by court (Supreme Court, High Court, etc.)\n"
            response += "   - Download PDF judgments directly\n\n"
            
            response += "**2. eCourts Services (https://services.ecourts.gov.in)**\n"
            response += "   - Official platform for case status\n"
            response += "   - Search by Case Number, Party Name, or Filing Number\n"
            response += "   - View orders, judgments, and cause lists\n\n"
            
            response += "**3. Supreme Court of India (https://main.sci.gov.in)**\n"
            response += "   - For Supreme Court cases\n"
            response += "   - Judgments database\n"
            response += "   - Case status tracking\n\n"
            
            response += "**4. High Court Websites**\n"
            response += "   - Each state has its High Court website\n"
            response +="   - Search for judgments and orders by case number\n\n"
            
            response += "**Note:** If this case is ongoing or recently filed, documents may not be publicly available yet. Court records typically become accessible after hearings or final judgments."
        
        elif option == 'C':
            # Option C: Legal analysis of specific aspect
            response = f"## Legal Analysis Options for: {last_topic}\n\n"
            response += "I can provide detailed legal analysis on specific aspects of this case. Please specify which aspect you'd like me to analyze:\n\n"
            
            response += "**1. Procedural Analysis**\n"
            response += "   - Court jurisdiction and competence\n"
            response += "   - Filing procedures and timelines\n"
            response += "   - Appeals and review mechanisms\n\n"
            
            response += "**2. Substantive Law Analysis**\n"
            response += "   - Relevant statutes and sections\n"
            response += "   - Elements of the offense/claim\n"
            response += "   - Defenses available\n\n"
            
            response += "**3. Evidentiary Analysis**\n"
            response += "   - Types of evidence required\n"
            response += "   - Admissibility standards\n"
            response += "   - Burden of proof\n\n"
            
            response += "**4. Precedent Analysis**\n"
            response += "   - Similar landmark cases\n"
            response += "   - How precedents apply\n"
            response += "   - Distinguishing factors\n\n"
            
            response += "**5. Remedies & Relief**\n"
            response += "   - Available legal remedies\n"
            response += "   - Interim relief options\n"
            response += "   - Execution of orders\n\n"
            
            response += "**How to proceed:** Please reply with the number (1-5) or describe the specific legal aspect you'd like me to analyze in detail."
        
        else:
            response = "Invalid option. Please select A, B, or C."
        
        # Return formatted response
        return {
            'answer': response,
            'context': f"Follow-up option {option} for: {last_topic}",
            'retrieved_id': f'follow_up_option_{option.lower()}',
            'sources': [],
            'timeline': None,
            'primary_documents': [],
            'latency': time.time() - start_time,
            'used_kaanoon': False,
            'extraction_method': 'follow_up_option',
            'detected_language': 'en',
            'complexity': 'simple',
            'session_id': session_id,
            'from_cache': False
        }
    
    def query(self, question: str, target_language: str = None, session_id: str = None, web_search_mode: bool = False) -> Dict[str, Any]:
        """
        LLM-FIRST ROUTING: LLM analyzes query, then decides RAG or direct response
        
        Args:
            web_search_mode: If True, perform comprehensive deep web search instead of normal RAG
        
        Returns:
            Dict with 'answer', 'context', 'retrieved_id', 'sources'
        """
        start_time = time.time()
        
        # ===== DEEP WEB SEARCH MODE =====
        if web_search_mode:
            print(f"[DEEP WEB SEARCH] Activated for: {question}")
            
            try:
                # Perform comprehensive web search using available engines
                all_results = []
                engines_used = []
                
                # Try web search client
                if hasattr(self, 'web_search_client') and self.web_search_client:
                    try:
                        # Try DuckDuckGo
                        ddg_results = self.web_search_client.search_duckduckgo(question, max_results=10)
                        all_results.extend(ddg_results or [])
                        if ddg_results:
                            engines_used.append('DuckDuckGo')
                    except Exception as e:
                        print(f"[WEB SEARCH] DuckDuckGo failed: {e}")
                    
                    # Try Serper if available
                    try:
                        if hasattr(self.web_search_client, 'search_serper'):
                            serper_results = self.web_search_client.search_serper(question, num_results=10)
                            all_results.extend(serper_results or [])
                            if serper_results:
                                engines_used.append('Serper')
                    except Exception as e:
                        print(f"[WEB SEARCH] Serper failed: {e}")
                
                # Deduplicate by URL
                seen_urls = set()
                unique_results = []
                for result in all_results:
                    url = result.get('url') or result.get('link')
                    if url and url not in seen_urls:
                        seen_urls.add(url)
                        unique_results.append(result)
                
                print(f"[WEB SEARCH] Found {len(unique_results)} unique results from {len(engines_used)} engines")
                
                # Generate comprehensive report
                if unique_results:
                    # Build context from results
                    context_parts = []
                    for i, r in enumerate(unique_results[:15], 1):
                        title = r.get('title', 'Untitled')
                        url = r.get('url') or r.get('link', '')
                        snippet = r.get('snippet') or r.get('description', '')
                        context_parts.append(f"{i}. **{title}**\n   URL: {url}\n   {snippet}")
                    
                    full_context = "\n\n".join(context_parts)
                    
                    # Comprehensive report prompt
                    prompt = f"""You are a comprehensive research assistant. Generate a detailed, well-sourced report.

QUERY: {question}

WEB SEARCH RESULTS ({len(unique_results)} sources):
{full_context[:8000]}

**REPORT FORMAT:**

## Executive Summary
(2-3 sentences explaining what happened and why it matters)

## Detailed Account
- Chronological breakdown with key facts
- Cite sources inline as (Source #1), (Source #2), etc.
- Include specific dates, names, numbers when available

## Key Findings
- Most important verified information
- Notable points from multiple sources
- Any contradictions or uncertainties

## Timeline (if applicable)
- Date: Event description (Source #X)

## Complete Source List
1. [Title](URL)
2. [Title](URL)
...

Generate comprehensive report now:"""
                    
                    # Call LLM
                    response = self.client.chat.completions.create(
                        model=self.model,
                        messages=[{"role": "user", "content": prompt}],
                        temperature=0.3,
                        max_tokens=2000
                    )
                    
                    comprehensive_report = response.choices[0].message.content
                    
                    return {
                        'answer': comprehensive_report,
                        'context': f"Deep web search: {len(unique_results)} sources from {', '.join(engines_used)}",
                        'sources': unique_results[:15],
                        'search_engines_used': engines_used,
                        'latency': time.time() - start_time,
                        'used_kaanoon': False,
                        'extraction_method': 'deep_web_search',
                        'detected_language': 'en',
                        'web_search_mode': True,
                        'session_id': session_id or 'no_session',
                        'from_cache': False
                    }
                else:
                    return {
                        'answer': "Deep web search did not return any results. Please check your query or try regular mode.",
                        'context': "No web search results",
                        'sources': [],
                        'latency': time.time() - start_time,
                        'web_search_mode': True
                    }
                    
            except Exception as e:
                print(f"[ERROR] Deep web search failed: {e}")
                import traceback
                traceback.print_exc()
                return {
                    'answer': f"Deep web search encountered an error: {str(e)}\n\nPlease try regular search mode.",
                    'error': str(e),
                    'latency': time.time() - start_time,
                    'web_search_mode': True
                }
        
        # ===== SMART NON-LEGAL QUERY DETECTION =====
        # Detect if query is NOT about Indian law
        question_lower = question.lower().strip()
        
        # Non-legal keywords that indicate general knowledge questions
        non_legal_indicators = [
            # Technology
            'artificial intelligence', 'ai technology', 'machine learning', 'deep learning',
            'what is ai', 'what is artificial', 'tell me about ai', 'explain ai',
            'computer science', 'programming', 'software', 'hardware',
            # Science
            'physics', 'chemistry', 'biology', 'mathematics', 'science',
            'history of', 'geography', 'astronomy', 'medicine', 'health',
            # General
            'cooking', 'recipe', 'sports', 'music', 'art', 'entertainment',
            'weather', 'climate', 'technology news', 'latest news',
            'how to cook', 'how to play', 'how to build', 'tutorial',
            # Current Events & News (NEW)
            'what happened', 'recent incident', 'latest update', 'breaking news',
            'news about', 'viral news', 'trending', 'current situation',
            'indigo flight', 'airline news', 'plane cancelled', 'flight cancelled',
            'why cancelled', 'why canceled', 'passenger incident', 'airport incident',
            'few days ago', 'recently happened', 'this week', 'last week',
            'today news', 'yesterday', 'current news', 'ongoing issue'
        ]
        
        # Check if question contains non-legal indicators
        is_non_legal = any(indicator in question_lower for indicator in non_legal_indicators)
        
        # Also check if question has NO legal keywords at all
        legal_keywords = [
            'law', 'legal', 'court', 'judge', 'lawyer', 'advocate', 'case', 'section',
            'act', 'article', 'ipc', 'crpc', 'cpc', 'constitution', 'sue', 'file',
            'complaint', 'fir', 'case', 'bail', 'rights', 'property', 'contract',
            'criminal', 'civil', 'petition', 'appeal', 'judgment', 'verdict'
        ]
        has_legal_keywords = any(keyword in question_lower for keyword in legal_keywords)
        
        if is_non_legal and not has_legal_keywords:
            # This is clearly a non-legal question - AUTO-ENABLE WEB SEARCH!
            print(f"[QUERY DETECTION] Non-legal query detected: {question}")
            print(f"[QUERY DETECTION] ⚡ AUTO-ACTIVATING WEB SEARCH MODE!")
            
            # FORCE web search mode for this query
            web_search_mode = True
            
            # Let it fall through to web search below
            print(f"[QUERY DETECTION] Redirecting to web search automatically...")

        try:
            conversation_context = ""
            last_topic = None
            last_answer = None
            
            if session_id and session_id in self.conversation_memory:
                # Get last 2 exchanges for context
                recent_history = self.conversation_memory[session_id][-2:]
                if recent_history:
                    context_parts = []
                    for prev_q, prev_a, topic in recent_history:
                        context_parts.append(f"User asked: {prev_q}")
                        if topic:
                            last_topic = topic
                        if prev_a:
                            last_answer = prev_a
                    conversation_context = "\n".join(context_parts)
            
            # ===== STEP 1: ULTRA-FAST PRE-CHECK for very common queries =====
            # This bypasses LLM routing for instant responses to reduce API latency
            question_lower = question.lower().strip()
            
            # Check if it's a follow-up question
            follow_up_patterns = [
                'tell in deep', 'tell me more', 'explain more', 'more detail', 'elaborate', 
                'tell more', 'in detail', 'explain detail', 'tell this in short', 'tell in short',
                'summarize', 'make it short', 'short answer', 'briefly', 'in brief', 
                'tell that in short', 'simplify', 'explain simply', 'tell this', 'tell that',
                'what about this', 'what about that', 'about this', 'about that', 'this',
                'give in short', 'give short', 'short', 'brief', 'summary', 'concise',
                'give me short', 'give me brief', 'chota', 'sankshipt',
                'और बताओ', 'और बताइए', 'संक्षेप में', 'छोटा जवाब'
            ]
            is_follow_up = any(pattern in question_lower for pattern in follow_up_patterns)
            
            # Additional check: If question contains "short" or "brief" and is under 10 words, treat as follow-up
            if not is_follow_up and len(question.split()) < 10 and any(w in question_lower for w in ['short', 'brief', 'summary']):
                 is_follow_up = True
            
            # Check for very short questions that are likely follow-ups
            if not is_follow_up and len(question.split()) <= 3 and last_topic:
                # Very short question with conversation history - likely a follow-up
                is_follow_up = True
            
            # ===== NEW: DETECT FOLLOW-UP OPTIONS (A/B/C) =====
            # Check if user is selecting one of the follow-up options we offered
            option_selected = None
            option_patterns = {
                'A': [r'^\(a\)$', r'^a$', r'^option a$', r'^\(a\)', r'^a\)', r'choose a', r'select a', r'option a$'],
                'B': [r'^\(b\)$', r'^b$', r'^option b$', r'^\(b\)', r'^b\)', r'choose b', r'select b', r'option b$'],
                'C': [r'^\(c\)$', r'^c$', r'^option c$', r'^\(c\)', r'^c\)', r'choose c', r'select c', r'option c$']
            }
            
            import re
            for option, patterns in option_patterns.items():
                for pattern in patterns:
                    if re.match(pattern, question_lower.strip()):
                        option_selected = option
                        break
                if option_selected:
                    break
            
            # If option selected, handle it directly
            if option_selected and last_answer:
                print(f"[FOLLOW-UP] User selected option {option_selected}")
                return self._handle_follow_up_option(option_selected, question, last_answer, last_topic, session_id)
            
            # If follow-up and we have context, handle it
            if is_follow_up and last_topic:
                print(f"[CONTEXT] Follow-up detected, topic: {last_topic}")
                
                # Check if user wants a SHORT answer
                wants_short = any(word in question_lower for word in ['short', 'brief', 'summarize', 'concise', 'संक्षेप', 'छोटा'])
                
                if wants_short and last_answer:
                    # Generate SHORT summary from previous answer
                    print(f"[SHORT ANSWER] Generating concise summary from previous answer")
                    latency = time.time() - start_time
                    
                    # Extract key points from previous answer (remove emojis and extra formatting)
                    clean_answer = re.sub(r'[🟩🟨🟦🟧]', '', last_answer)
                    clean_answer = re.sub(r'(Answer|Analysis|Legal Basis|Conclusion|References)', '', clean_answer)
                    
                    # Take first 2-3 sentences or up to 300 chars
                    sentences = [s.strip() + '.' for s in clean_answer.split('.') if s.strip() and len(s.strip()) > 20]
                    short_summary = ' '.join(sentences[:2])  # First 2 sentences
                    
                    if len(short_summary) > 400:
                        short_summary = short_summary[:397] + "..."
                    
                    # Store in conversation memory
                    if session_id:
                        if session_id not in self.conversation_memory:
                            self.conversation_memory[session_id] = []
                        self.conversation_memory[session_id].append((question, short_summary, last_topic))
                        if len(self.conversation_memory[session_id]) > 5:
                            self.conversation_memory[session_id] = self.conversation_memory[session_id][-5:]
                    
                    return {
                        'answer': short_summary,
                        'title': self.generate_query_title(question),
                        'context': 'Short summary from previous answer',
                        'retrieved_id': 'short_summary',
                        'sources': [],
                        'latency': latency,
                        'used_kaanoon': False,
                        'extraction_method': 'short_summary',
                        'detected_language': target_language or 'en',
                        'fast_response': True,
                        'complexity': 'trivial',
                        'query_type': 'short_summary',
                        'routing_confidence': 1.0
                    }
                elif wants_short:
                    # No previous answer but wants short - reformulate
                    question = f"Give a brief 2-3 sentence summary about {last_topic}"
                else:
                    # Regular follow-up
                    question = f"{question} about {last_topic}"
            
            # Single-word greetings (instant response)
            if question_lower in ['hi', 'hello', 'hey', 'hii', 'namaste', 'helo', 'thanks', 'bye']:
                latency = time.time() - start_time
                greeting_responses = {
                    'hi': "Hello! I'm your AI legal assistant for Indian law. How can I help you today?",
                    'hello': "Hello! I'm your AI legal assistant. What legal question do you have?",
                    'hey': "Hey! I'm here to help with your legal queries. What would you like to know?",
                    'hii': "Hello! I'm your AI legal assistant. How can I help you today?",
                    'namaste': "Namaste! I'm your legal assistant. What legal question can I help you with?",
                    'helo': "Hello! I'm your AI legal assistant. How can I help you today?",
                    'thanks': "You're welcome! If you have any more legal questions, I'm here to help.",
                    'bye': "Goodbye! Feel free to return anytime you need legal assistance."
                }
                
                print(f"[INSTANT RESPONSE] Ultra-fast greeting - {latency*1000:.0f}ms")
                return {
                    'answer': greeting_responses.get(question_lower, greeting_responses['hi']),
                    'title': "Welcome",
                    'context': 'Instant greeting response',
                    'retrieved_id': 'instant_greeting',
                    'sources': [],
                    'latency': latency,
                    'used_kaanoon': False,
                    'extraction_method': 'instant',
                    'detected_language': target_language or 'en',
                    'fast_response': True,
                    'complexity': 'trivial',
                    'query_type': 'greeting',
                    'routing_confidence': 1.0
                }
            
            # Common capability questions (instant response)
            if any(phrase in question_lower for phrase in ['what can you', 'what all', 'what help', 'what you can']):
                latency = time.time() - start_time
                print(f"[INSTANT RESPONSE] Capabilities query - {latency*1000:.0f}ms")
                return {
                    'answer': "I can help you with Indian legal questions including:\n\n• IPC (Indian Penal Code) - sections, penalties, procedures\n• GST and tax law - rates, compliance, filing\n• DPDP Act (data protection) - consent, processing rules\n• Property and contract law\n• Legal procedures and compliance\n• Case law and precedents\n\nWhat specific legal question do you have?",
                    'title': "My Capabilities",
                    'context': 'Instant capabilities response',
                    'retrieved_id': 'instant_capabilities',
                    'sources': [],
                    'latency': latency,
                    'used_kaanoon': False,
                    'extraction_method': 'instant',
                    'detected_language': target_language or 'en',
                    'fast_response': True,
                    'complexity': 'trivial',
                    'query_type': 'about_ai',
                    'routing_confidence': 1.0
                }
            
            # ===== STEP 0.5: ADVANCED INPUT ANALYSIS =====
            # Analyze user input for intent, entities, sentiment, safety
            input_analysis = None
            if self.input_analyzer:
                try:
                    input_analysis = self.input_analyzer.analyze(
                        question, 
                        conversation_history=self.conversation_memory.get(session_id, [])
                    )
                    
                    # Handle safety violations
                    if input_analysis['safety_flag']:
                        safety_response = f"""⚠️ **I cannot assist with this request**

**Reason:** {input_analysis['safety_reason']}

**Why I'm designed this way:**
I'm a legal AI assistant designed to provide ethical, legitimate legal guidance. I cannot:
• Help with illegal activities or fraud
• Create fake documents or evidence
• Advise on tax evasion or money laundering
• Assist with deception or harm to others

**What I CAN help with:**
• ✅ Understanding your legal rights and obligations
• ✅ Legal ways to resolve disputes
• ✅ Legitimate tax planning strategies
• ✅ Defending yourself against false accusations
• ✅ Knowing your options within the law

**Please ask about legitimate legal matters, and I'll be happy to help!**"""
                        
                        return {
                            'answer': safety_response,
                            'context': '',
                            'retrieved_id': 'safety_filter',
                            'sources': [],
                            'latency': time.time() - start_time,
                            'used_kaanoon': False,
                            'extraction_method': 'safety_filter',
                            'detected_language': 'en',
                            'input_analysis': input_analysis
                        }
                    
                    # Handle ambiguous queries that need clarification
                    # BUT: Skip clarification for factual/educational queries
                    # Handle ambiguous queries that need clarification
                    # BUT: Skip clarification for factual/educational queries
                    # if input_analysis['clarification_needed'] and input_analysis['clarifying_questions']:
                        # PASS THROUGH FOR 95% ACCURACY
                        # pass
                        # Use the comprehensive query type detection method
                        # detected_response_type = self.detect_query_response_type(question)
                        
                        # If it's educational/factual (not legal advice), skip clarification and proceed to RAG
                        # if True: # FORCE RAG - Optimization for 95% Accuracy
                        #    print(f"[CLARIFICATION SKIP] Optimization verified, proceeding to RAG")
                        # else:
                        #    # Only ask for clarification if it's truly ambiguous (personal legal matter)
                        #    clarifying_response = "I'd like to understand your situation better to provide accurate advice.\n\n"
                        #    clarifying_response += "**Please clarify:**\n\n"
                        #    for i, question in enumerate(input_analysis['clarifying_questions'], 1):
                        #        clarifying_response += f"{i}. {question}\n"
                        #    clarifying_response += "\nOnce I have these details, I can provide comprehensive legal guidance."
                            
                        #    return {
                        #        'answer': clarifying_response,
                        #        'context': '',
                        #        'retrieved_id': 'clarification_request',
                        #        'sources': [],
                        #        'latency': time.time() - start_time,
                        #        'used_kaanoon': False,
                        #        'extraction_method': 'clarification',
                        #        'detected_language': 'en',
                        #        'input_analysis': input_analysis
                        #    }
                    
                    # Log analysis for debugging
                    print(f"[INPUT ANALYSIS] Intent: {input_analysis['intent']}, Domain: {input_analysis['domain']}, Sentiment: {input_analysis['sentiment']}, Complexity: {input_analysis['metadata']['complexity']}")
                    
                except Exception as e:
                    print(f"[WARNING] Input analysis failed: {e}")
                    input_analysis = None
            

            
            # ===== STEP 2: LLM ANALYZES IF RAG IS NEEDED (with conversation context & timeout) =====
            print(f"\n[LLM ROUTING] Analyzing query: {question[:60]}...")
            if conversation_context:
                print(f"[CONTEXT] Using conversation history for context")
            
            try:
                routing = self.llm_analyze_routing(question, conversation_context)
                print(f"[LLM ROUTING] Decision: needs_rag={routing.get('needs_rag')}, can_answer={routing.get('can_answer_directly')}, type={routing.get('query_type')}, title={routing.get('response_title')}, confidence={routing.get('confidence', 0):.2f}")
            except Exception as e:
                print(f"[ERROR] LLM routing failed: {e}, proceeding to RAG")
                routing = {
                    'needs_rag': True,
                    'can_answer_directly': False,
                    'direct_answer': None,
                    'response_title': None,
                    'query_type': 'routing_error',
                    'confidence': 0.5
                }
            
            # ===== STEP 2A: DIRECT RESPONSE PATH (No RAG) =====
            # CRITICAL: Force ALL legal queries through RAG for professional format
            # Only allow direct responses for greetings/about_ai
            query_type = routing.get('query_type', '')
            is_legal_query = query_type in ['simple_legal', 'complex_legal', 'procedural']
            
            if routing['can_answer_directly'] and routing['direct_answer'] and not is_legal_query:
                latency = time.time() - start_time
                print(f"[DIRECT RESPONSE] {routing.get('query_type', 'direct')} query - {latency*1000:.0f}ms")
                
                # Store in conversation memory
                if session_id:
                    if session_id not in self.conversation_memory:
                        self.conversation_memory[session_id] = []
                    # Extract topic from answer for context
                    topic = routing.get('response_title') or question[:50]
                    self.conversation_memory[session_id].append((question, routing['direct_answer'][:100], topic))
                    # Keep only last 5 exchanges
                    if len(self.conversation_memory[session_id]) > 5:
                        self.conversation_memory[session_id] = self.conversation_memory[session_id][-5:]
                
                return {
                    'answer': routing['direct_answer'],
                    'title': routing.get('response_title'),  # LLM-generated title
                    'context': f"Direct LLM response ({routing.get('query_type', 'direct')})",
                    'retrieved_id': 'direct_llm',
                    'sources': [],
                    'latency': latency,
                    'used_kaanoon': False,
                    'extraction_method': 'llm_direct',
                    'detected_language': target_language or 'en',
                    'fast_response': True,
                    'complexity': 'trivial',
                    'query_type': routing.get('query_type', 'direct'),
                    'routing_confidence': routing.get('confidence', 1.0)
                }
            
            # ===== STEP 2B: RAG PATH (Needs documents) =====
            print(f"[RAG PATH] Retrieving legal documents...")
            
            # ===== IPC FAST LOOKUP (within RAG path) =====
            # Match patterns: "IPC 302", "What is IPC 302?", "IPC Section 302", "Section 302", "302 IPC"
            question_upper = question.upper()
            ipc_section = None
            
            # Extract any 3-digit number from question
            all_numbers = re.findall(r'\b(\d{3}[A-Z]?)\b', question)
            if all_numbers:
                # Check if question mentions IPC/Section
                has_ipc_context = (
                    'IPC' in question_upper or 
                    'SECTION' in question_upper or
                    'INDIAN PENAL CODE' in question_upper
                )
                if has_ipc_context:
                    # Use first 3-digit number found (IPC sections are typically 3 digits)
                    ipc_section = all_numbers[0]
                # Also check for direct patterns
                else:
                    # Try direct patterns first
                    patterns = [
                        (r'\bipc\s+(\d+[A-Z]?)\b', question, True),
                        (r'\bipc\s+section\s+(\d+[A-Z]?)\b', question, True),
                        (r'\bsection\s+(\d+[A-Z]?)\b', question_upper, True),
                        (r'\b(\d+[A-Z]?)\s+ipc\b', question_upper, True),
                    ]
                    for pattern, text, case_sensitive in patterns:
                        match = re.search(pattern, text, re.IGNORECASE if not case_sensitive else 0)
                        if match:
                            ipc_section = match.group(1)
                            break
            
            # FAST LOOKUP: Return instantly if IPC section found
            if ipc_section and ipc_section in self.IPC_SECTIONS_FAST_LOOKUP:
                ipc_data = self.IPC_SECTIONS_FAST_LOOKUP[ipc_section]
                detected_lang = target_language or 'en'  # Skip language detection for speed
                
                # Format complete response instantly
                # Format complete response instantly in STANDARD 9-POINT FORMAT
                formatted_answer = f"""Below is the ONLY CORRECT RESPONSE FORMAT for a Law Chatbot.
No answers. No explanations. Format only. Minimal emojis.

⚡ EXECUTIVE SUMMARY

{ipc_data['answer'].split('.')[0]}. punishment is prescribed under this section.

❓ ISSUES FOR DETERMINATION
(Issues related to the offense and punishment under IPC {ipc_section})

📜 APPLICABLE LAW
A. Constitutional Provisions

Article ___ : (If applicable)

B. Statutory Provisions

Indian Penal Code, 1860 – Section {ipc_section}

{ipc_data['title']}

C. Judicial Doctrines / Principles

Doctrine / Test name

Principle

🧠 LEGAL ANALYSIS (IRAC)
A. Rule (Settled Position of Law)
{ipc_data['answer']}

B. Application to Facts
(Analysis based on specific facts if provided)

C. Counter-Arguments & Judicial Response

Counter-argument:

Likely judicial view:

📚 JUDICIAL PRECEDENTS

Case Name (Year) – Ratio

Case Name (Year) – Ratio

🧾 PROCEDURAL ASPECTS

Maintainability:

Jurisdiction: Criminal Courts (Magistrate/Sessions Court depending on schedule)

Burden of proof:

Stage of proceedings:

⚖️ POSSIBLE OUTCOMES

Outcome A: Conviction (Penalty: {ipc_data['penalty']})

Outcome B: Acquittal

Outcome C: Bail

✅ FINAL LEGAL POSITION

Reasoned, non-conclusive position ⚖️

This is a statutory provision defining the offense and its consequences.

🛠️ STYLE & OUTPUT RULES (FOR LAW BOT)

Neutral tone

No absolute conclusions

Structured headings only

Cite law before opinion

Emojis limited to ⚖️ 📜"""
                
                return {
                    'answer': formatted_answer,
                    'context': f"Fast lookup for IPC Section {ipc_section}",
                    'retrieved_id': f'IPC_{ipc_section}',
                    'sources': [{'rank': 1, 'score': 1.0, 'source': 'IPC Fast Lookup', 'category': 'IPC', 'is_kaanoon': False}],
                    'latency': time.time() - start_time,
                    'used_kaanoon': False,
                    'extraction_method': 'fast_lookup',
                    'detected_language': detected_lang,
                    'fast_response': True
                }
            
            # ===== ULTRA-FAST PATH: Check for legal definition/acronym queries =====
            # Analyze question structure first to detect definition questions
            question_analysis = self.analyze_question_structure(question)
            
            # Check if this is a definition/acronym question with fast lookup available
            if question_analysis.get('is_definition') and question_analysis.get('is_acronym'):
                acronym = question_analysis.get('acronym')
                if acronym and acronym in self.LEGAL_DEFINITIONS_FAST_LOOKUP:
                    def_data = self.LEGAL_DEFINITIONS_FAST_LOOKUP[acronym]
                    detected_lang = target_language or 'en'  # Skip language detection for speed
                    
                    # Format complete response instantly
                    # Format complete response instantly in STANDARD 9-POINT FORMAT
                    formatted_answer = f"""Below is the ONLY CORRECT RESPONSE FORMAT for a Law Chatbot.
No answers. No explanations. Format only. Minimal emojis.

⚡ EXECUTIVE SUMMARY

{acronym} stands for {def_data['full_form']}. {def_data['definition'].split('.')[0]}.

❓ ISSUES FOR DETERMINATION
(Issues related to the definition and application of {acronym})

📜 APPLICABLE LAW
A. Constitutional Provisions

Article ___ : (If applicable)

Article ___ : (If applicable)

B. Statutory Provisions

{def_data.get('year', 'N/A')} Enactment – Section ___

{', '.join(def_data.get('key_sections', []))}

C. Judicial Doctrines / Principles

Doctrine / Test name

Principle

🧠 LEGAL ANALYSIS (IRAC)
A. Rule (Settled Position of Law)
{def_data['definition']}

B. Application to Facts
(Analysis based on specific facts if provided)

C. Counter-Arguments & Judicial Response

Counter-argument:

Likely judicial view:

📚 JUDICIAL PRECEDENTS

Case Name (Year) – Ratio

Case Name (Year) – Ratio

🧾 PROCEDURAL ASPECTS

Maintainability: Applicable across relevant courts/tribunals.

Jurisdiction:

Burden of proof:

Stage of proceedings:

⚖️ POSSIBLE OUTCOMES

Outcome A:

Outcome B:

Outcome C:

✅ FINAL LEGAL POSITION

Reasoned, non-conclusive position ⚖️

This term is fundamental to the understanding of the relevant legal framework.

🛠️ STYLE & OUTPUT RULES (FOR LAW BOT)

Neutral tone

No absolute conclusions

Structured headings only

Cite law before opinion

Emojis limited to ⚖️ 📜"""
                    
                    return {
                        'answer': formatted_answer,
                        'context': f"Fast lookup for {acronym} definition",
                        'retrieved_id': f'DEF_{acronym}',
                        'sources': [{'rank': 1, 'score': 1.0, 'source': 'Legal Definitions Fast Lookup', 'category': 'Definition', 'is_kaanoon': False}],
                        'latency': time.time() - start_time,
                        'used_kaanoon': False,
                        'extraction_method': 'fast_lookup_definition',
                        'detected_language': detected_lang,
                        'fast_response': True
                    }
            
            # Analyze query complexity for time-based optimization (pass question_analysis to avoid re-computing)
            try:
                complexity_info = self._analyze_complexity_logic(question, question_analysis)
                print(f"[DEBUG] complexity_info type: {type(complexity_info)}, content: {complexity_info}")
                if isinstance(complexity_info, float):
                    raise ValueError(f"complexity_info is float: {complexity_info}")
                complexity_level = complexity_info['complexity']
            except Exception as e:
                import traceback
                tb = traceback.format_exc()
                print(f"[ERROR] Complexity analysis failed: {e}\n{tb}")
                return {
                    'answer': f"Error in complexity analysis: {e}\n\nTraceback:\n{tb}",
                    'context': str(complexity_info) if 'complexity_info' in locals() else "Not computed",
                    'retrieved_id': 'error_debug',
                    'sources': [],
                    'latency': 0.0,
                    'used_kaanoon': False,
                    'extraction_method': 'error',
                    'detected_language': 'en',
                    'fast_response': True
                }
            is_simple_query = complexity_level in ['ultra_simple', 'simple']
            max_time = complexity_info['max_time_seconds']
            time_budget = complexity_info.get('time_budget', {
                'retrieval': max_time * 0.25,
                'processing': max_time * 0.15,
                'llm': max_time * 0.60,
                'total': max_time
            })
            
            # Log complexity analysis
            print(f"[COMPLEXITY] Query: '{question[:50]}...' → {complexity_level.upper()} (target: {max_time}s, indicators: {complexity_info['indicators']})")
            print(f"[ANALYSIS] Question type: {question_analysis.get('question_type')}, Legal domains: {question_analysis.get('legal_domains')}")
            
            # Detect language if not provided
            detected_lang = target_language or self.detect_language_from_query(question)
            
            # ===== TEMPORAL/FRESHNESS DETECTION =====
            # Force web search for queries needing recent/trending data
            temporal_keywords = ["2023", "2024", "2025", "2026", "latest", "recent", "news", "current", "new", "today", "this year"]
            needs_fresh_data = any(kw in question.lower() for kw in temporal_keywords)
            web_context_fresh = ""
            
            if needs_fresh_data:
                print(f"[FRESH DATA] Temporal keyword detected in query, forcing web search...")
                if hasattr(self, 'enricher'):
                    web_context_fresh = self.enricher.get_web_context(question)
                    if web_context_fresh:
                        print(f"[WEB SEARCH] Retrieved fresh data from web ({len(web_context_fresh)} chars)")
                    else:
                        print(f"[WEB SEARCH] No fresh data found from web")
            
            # Retrieve relevant documents with AGGRESSIVE optimization
            # CRITICAL: Retrieval is the bottleneck - optimize heavily
            retrieval_start = time.time()
            retrieval_time_budget = max_time * 0.20 if is_simple_query else max_time * 0.25  # Reduced budget
            
            # For very simple queries (<=5 words), use ultra-fast retrieval
            word_count = len(question.split())
            use_ultra_fast = is_simple_query and word_count <= 5
            
            # CRITICAL OPTIMIZATION: Enable Re-ranking for Accuracy
            # Re-ranking is essential for finding specific case law (Hadiya, Vidya Devi)
            # Hybrid search needs reranking to bubble up keyword matches
            skip_reranking = False  # ENABLED for 95% Accuracy target
            skip_expansion = use_ultra_fast or complexity_level in ['ultra_simple', 'simple']
            
            print(f"[RETRIEVAL] Optimizations: rerank=False (DISABLED), expand={not skip_expansion}")
            
            results = self.retriever.retrieve(
                question,
                use_reranking=True,  # ALWAYS RERANK for 95% Accuracy
                use_query_expansion=not skip_expansion,
                top_k=50  # Boosted from 25 to 50 for deep coverage
            )
            
            # Massive increase in result limits to provide more context
            if is_simple_query:
                if use_ultra_fast:
                    results = results[:8]  # Increased from 3
                else:
                    results = results[:12]  # Increased from 5
            else:
                results = results[:20]  # Increased from 6-8
            
            retrieval_time = time.time() - retrieval_start
            if retrieval_time > retrieval_time_budget:
                print(f"[WARNING] Retrieval took {retrieval_time:.2f}s (budget: {retrieval_time_budget:.2f}s)")
            
            # Check if we're running out of time
            elapsed_time = time.time() - start_time
            remaining_time = max_time - elapsed_time
            
            # EMERGENCY FALLBACK: If retrieval took too long, use FAST Cerebras generation
            if retrieval_time > max_time * 0.5:  # Used >50% of time on retrieval
                print(f"[EMERGENCY] Retrieval took {retrieval_time:.2f}s (>{max_time*0.5:.1f}s), using FAST LLM generation")
                
                if results:
                    # Build context from top 3 results
                    context_emergency, _, _ = self.select_best_context(results[:3], question, max_chars=1200)
                    
                    if not context_emergency or len(context_emergency) < 50:
                        # No good context - return helpful message
                        return {
                            'answer': f"I understand you're asking about: **{question}**\n\nUnfortunately, I couldn't find specific legal information about this topic in the time available. Please try:\n\n• Rephrasing your question\n\n• Making it more specific\n\n• Breaking it into simpler parts",
                            'context': None,
                            'retrieved_id': 'emergency_no_context',
                            'sources': [],
                            'latency': elapsed_time,
                            'used_kaanoon': False,
                            'extraction_method': 'emergency_no_results',
                            'detected_language': detected_lang,
                            'fast_response': True
                        }
                    
                    # FAST Cerebras generation with PROFESSIONAL FORMAT
                    print(f"[EMERGENCY] Generating professional response with Cerebras (max 6000 tokens for complete format)")
                    # Use the full professional prompt for consistency
                    fast_prompt = self.build_intelligent_prompt(question, context_emergency[:2000], has_kaanoon=False, question_analysis=None)
                    
                    try:
                        response = self.client.chat.completions.create(
                            model=self.model,
                            messages=[{"role": "user", "content": fast_prompt}],
                            temperature=0.0,
                            max_tokens=6000,  # Professional format needs full space for all 6 mandatory sections
                            timeout=10.0  # Allow more time for complete 6-section response
                        )
                        
                        answer = response.choices[0].message.content.strip()
                        print(f"[EMERGENCY] Got fast response in {time.time() - start_time:.2f}s")
                        
                        return {
                            'answer': answer,
                            'context': context_emergency[:500],
                            'retrieved_id': 'emergency_fast_llm',
                            'sources': [{'rank': i+1, 'score': r.get('rerank_score', r.get('rrf_score', 0))} for i, r in enumerate(results[:3])],
                            'latency': time.time() - start_time,
                            'used_kaanoon': False,
                            'extraction_method': 'emergency_fast_generation',
                            'detected_language': detected_lang,
                            'fast_response': True
                        }
                    except Exception as e:
                        print(f"[EMERGENCY] Fast LLM failed: {e}, returning formatted context")
                        # Fallback: Return formatted context
                        formatted_context = self._format_context_as_answer(context_emergency, question)
                        return {
                            'answer': formatted_context,
                            'context': context_emergency[:500],
                            'retrieved_id': 'emergency_context',
                            'sources': [{'rank': i+1, 'score': r.get('rerank_score', r.get('rrf_score', 0))} for i, r in enumerate(results[:3])],
                            'latency': elapsed_time,
                            'used_kaanoon': False,
                            'extraction_method': 'emergency_formatted_context',
                            'detected_language': detected_lang,
                            'fast_response': True
                        }
            
            if remaining_time < 1.0:
                print(f"[WARNING] Only {remaining_time:.2f}s remaining, accelerating response")
            
            if not results:
                # NO DOCUMENTS FOUND - Try Web Search first
                print(f"[NO DOCS] No local documents. Attempting Web Search...")
                
                web_context = ""
                if hasattr(self, 'enricher'):
                     web_context = self.enricher.get_web_context(question)
                
                if web_context:
                    print(f"[WEB SEARCH] Found external information")
                    context_source = "Web Search Results"
                    final_context = web_context
                else:
                    print(f"[NO WEB RESULTS] Using LLM general knowledge")
                    context_source = "General Legal Principles (No specific documents found)"
                    final_context = ""

                # DETECT QUESTION TYPE: Simple factual vs Complex dispute
                question_lower = question.lower()
                is_simple_factual = any([
                    question_lower.startswith(('what is', 'what are', 'define', 'explain', 'how many')),
                    'types of' in question_lower,
                    'difference between' in question_lower,
                    'meaning of' in question_lower,
                    'definition' in question_lower,
                    len(question.split()) < 15,
                ]) and not any([
                    'my ' in question_lower,
                    'claim' in question_lower and ('denied' in question_lower or 'rejected' in question_lower),
                    'tenant' in question_lower and 'refuses' in question_lower,
                    'not paid' in question_lower,
                    'dispute' in question_lower,
                    'fraud' in question_lower,
                    'evict' in question_lower,
                    'recover' in question_lower and 'money' in question_lower,
                    'filed' in question_lower and ('fir' in question_lower or 'case' in question_lower),
                ])
                
                try:
                    # Build prompt using Legal Reasoning Engine
                    if self.reasoning_engine:
                        general_prompt = self.reasoning_engine.construct_structured_prompt(question, final_context or context_source, "")
                    else:
                        general_prompt = f"You are an expert legal AI assistant. QUESTION: {question}\n\nPlease provide a structured answer."

                    response = self.client.chat.completions.create(
                        model=self.model,
                        messages=[{"role": "user", "content": general_prompt}],
                        temperature=0.1,
                        max_tokens=2000
                    )
                    
                    general_answer = response.choices[0].message.content.strip()
                    
                    # Validate response with LRE
                    if self.reasoning_engine:
                        validation = self.reasoning_engine.validate_response(general_answer)
                        if not validation['valid']:
                            print(f"[LRE] Validation Warning: {validation['issues']}")
                            # We could append a warning, but for now just log it

                    # Generate title
                    response_title = self.generate_query_title(question, general_answer)
                    
                    return {
                        'answer': general_answer,
                        'title': response_title,
                        'context': 'Based on general legal knowledge',
                        'retrieved_id': 'general_knowledge',
                        'sources': [],
                        'latency': time.time() - start_time,
                        'used_kaanoon': False,
                        'extraction_method': 'llm_general_knowledge',
                        'detected_language': target_language or 'en',
                        'note': 'Answered using general legal knowledge as specific case documents were not found in database'
                    }
                except Exception as e:
                    print(f"[ERROR] LLM general knowledge failed: {e}")
                    return {
                        'answer': "I apologize, but I couldn't find specific legal documents for your question. Please try rephrasing your question or consult with a legal professional for personalized advice.",
                        'title': self.generate_query_title(question),
                        'context': None,
                        'retrieved_id': None,
                        'sources': [],
                        'error': 'No results found and LLM fallback failed'
                    }
            
            # Select best context and check for Kaanoon Q&A (adjust context size based on complexity)
            processing_start = time.time()
            processing_time_budget = time_budget['processing']
            
            # AGGRESSIVE context size reduction for speed
            if complexity_level == 'ultra_simple':
                context_max_chars = 400
            elif is_simple_query:
                context_max_chars = 800
            elif complexity_level == 'moderate':
                context_max_chars = 1200  # Reduced from 1500
            else:
                context_max_chars = 2000  # Reduced from 2500
            
            context, has_kaanoon, kaanoon_docs = self.select_best_context(results, question, max_chars=context_max_chars)
            
            # Merge web context if temporal query
            if web_context_fresh:
                context = web_context_fresh + "\n\n===== LOCAL LEGAL DATABASE =====\n\n" + context
                print(f"[HYBRID] Merged web search + local retrieval ({len(context)} chars total)")
            
            processing_time = time.time() - processing_start
            
            # Check processing time
            if processing_time > processing_time_budget:
                print(f"[TIME ENFORCEMENT] Processing took {processing_time:.2f}s (budget: {processing_time_budget:.2f}s)")
                # Truncate context if needed
                if context and len(context) > context_max_chars:
                    context = context[:context_max_chars]
            
            # Check total elapsed time before LLM call
            elapsed_time = time.time() - start_time
            remaining_time = max_time - elapsed_time
            llm_time_budget = time_budget['llm']
            
            # STRICT ENFORCEMENT: If less than LLM budget remaining, reduce tokens or skip LLM
            if remaining_time < llm_time_budget * 0.5:
                print(f"[TIME ENFORCEMENT] Only {remaining_time:.2f}s remaining for LLM (budget: {llm_time_budget:.2f}s), using context fallback")
                answer = context[:1500] if context else "I found relevant information but couldn't generate a complete answer within the time limit. Please try rephrasing your question."
                extraction_method = 'time_limit_fallback'
            else:
                # Smart extraction: If Kaanoon Q&A was retrieved
                if has_kaanoon and kaanoon_docs:
                    # Get Kaanoon Q&A ID and confidence score
                    qa_id = kaanoon_docs[0].get('metadata', {}).get('qa_id')
                    rerank_score = kaanoon_docs[0].get('rerank_score', 0)
                
                    # Intelligent matching: Use semantic similarity and confidence scoring
                    # Instead of hardcoded threshold, use intelligent matching
                    qa_match_confidence = self.calculate_qa_match_confidence(question, kaanoon_docs[0], qa_id)
                    
                    # Strategy 1: High confidence exact match - use stored answer
                    # Use intelligent confidence scoring instead of hardcoded threshold
                    if qa_id in self.KAANOON_EXACT_ANSWERS and (qa_match_confidence > 0.75 or rerank_score > 5.0):
                        # Very high confidence - this is the exact question
                        # Use language-specific mapping if available
                        if detected_lang == 'hi' and qa_id in self.KAANOON_EXACT_ANSWERS_HI:
                            answer = self.KAANOON_EXACT_ANSWERS_HI[qa_id]
                        elif detected_lang == 'ta' and qa_id in self.KAANOON_EXACT_ANSWERS_TA:
                            answer = self.KAANOON_EXACT_ANSWERS_TA[qa_id]
                        else:
                            answer = self.KAANOON_EXACT_ANSWERS[qa_id]
                        extraction_method = 'exact_match'
                    elif rerank_score > 4.0 and qa_id:
                        # Strategy 2: Medium confidence - try extraction from Kaanoon Q&A first
                        print(f"[INFO] Medium confidence match (score: {rerank_score:.2f}), extracting from Kaanoon Q&A")
                        extracted = self.extract_answer_from_kaanoon_qa(kaanoon_docs[0])
                        if extracted and len(extracted) > 150:  # If we got a good extraction
                            answer = extracted
                            extraction_method = 'extracted_from_kaanoon'
                            print(f"[INFO] Successfully extracted {len(answer)} chars from Kaanoon Q&A")
                        else:
                            # Fallback to LLM generation if extraction failed
                            # Check time before LLM call
                            elapsed_before_llm = time.time() - start_time
                            remaining_for_llm = max_time - elapsed_before_llm
                            
                            if remaining_for_llm < llm_time_budget * 0.3:
                                print(f"[TIME ENFORCEMENT] Insufficient time for LLM ({remaining_for_llm:.2f}s), using context fallback")
                                answer = context[:1500] if context else "I found relevant information but couldn't generate a complete answer within the time limit."
                                extraction_method = 'time_limit_fallback'
                            else:
                                # AGGRESSIVE token limits for speed
                                if remaining_for_llm < 3.0:
                                    # Very little time left - use context fallback
                                    print(f"[FAST FALLBACK] Only {remaining_for_llm:.2f}s left, using context directly")
                                    answer = f"Based on legal sources:\n\n{context[:1000]}\n\n[Note: Showing direct context for speed]" if context else "Time limit exceeded."
                                    extraction_method = 'time_limit_fallback'
                                elif remaining_for_llm < llm_time_budget:
                                    max_tokens = 6000  # Full format even under time pressure
                                else:
                                    max_tokens = 6000  # Full format always
                                
                                prompt = self.build_intelligent_prompt(question, context, has_kaanoon=True, question_analysis=question_analysis)
                                try:
                                    from concurrent.futures import ThreadPoolExecutor, TimeoutError as FuturesTimeoutError
                                    
                                    llm_start = time.time()
                                    timeout_seconds = min(remaining_for_llm, 5.0)  # Max 5 seconds (reduced from 8)
                                    
                                    def make_answer_call():
                                        return self.client.chat.completions.create(
                                            model=self.model,
                                            messages=[{"role": "user", "content": prompt}],
                                            temperature=0.0,
                                            max_tokens=max_tokens,
                                            timeout=timeout_seconds
                                        )
                                    
                                    # Execute with timeout
                                    with ThreadPoolExecutor(max_workers=1) as executor:
                                        future = executor.submit(make_answer_call)
                                        response = future.result(timeout=timeout_seconds + 1.0)
                                    
                                    llm_time = time.time() - llm_start
                                    
                                    # Check if LLM exceeded budget
                                    if llm_time > remaining_for_llm:
                                        print(f"[TIME ENFORCEMENT] LLM took {llm_time:.2f}s (remaining: {remaining_for_llm:.2f}s)")
                                    
                                    print(f"[LLM] Generation took {llm_time:.2f}s (budget: {llm_time_budget:.2f}s)")
                                    answer = response.choices[0].message.content.strip()
                                    extraction_method = 'llm_generated'
                                except FuturesTimeoutError:
                                    # Timeout - use context directly
                                    print(f"[TIMEOUT] Answer generation timed out after {timeout_seconds}s")
                                    if context:
                                        answer = f"Based on the legal documents retrieved:\\n\\n{context[:800]}\\n\\n[Note: Full answer generation timed out. The above information is directly from legal sources.]"
                                    else:
                                        answer = "The query is complex and requires more time to process. Please try breaking it into smaller, specific questions."
                                    extraction_method = 'timeout_context_fallback'
                                except Exception as e:
                                    # Use context as final fallback
                                    print(f"[ERROR] API call failed: {e}, using context fallback")
                                    if context:
                                        answer = f"Based on retrieved legal information:\\n\\n{context[:800]}"
                                    else:
                                        answer = "I found relevant information but couldn't generate a complete answer. Please try rephrasing your question."
                                    extraction_method = 'error_context_fallback'
                    else:
                        # Strategy 3: Lower confidence - generate with LLM using intelligent prompt
                        # Adjust tokens based on complexity and question type
                        word_count = len(question.split())
                        use_ultra_fast = is_simple_query and word_count <= 5
                        
                        # PROFESSIONAL FORMAT from Kaanoon needs MAXIMUM tokens for all 6 sections
                        if question_analysis.get('question_type') == 'multi_part':
                            max_tokens = 6000  # Multi-part: comprehensive with all sections
                        elif question_analysis.get('requires_procedure'):
                            max_tokens = 6000  # Procedural: detailed steps + all sections
                        elif use_ultra_fast:
                            max_tokens = 6000  # Ultra-fast: complete format required
                        else:
                            max_tokens = 6000  # Professional format needs space for all 6 sections
                        # Check time before LLM call
                        elapsed_before_llm = time.time() - start_time
                        remaining_for_llm = max_time - elapsed_before_llm
                        
                        if remaining_for_llm < llm_time_budget * 0.3:
                            print(f"[TIME ENFORCEMENT] Insufficient time for LLM ({remaining_for_llm:.2f}s), using context fallback")
                            answer = context[:1500] if context else "I found relevant information but couldn't generate a complete answer within the time limit."
                            extraction_method = 'time_limit_fallback'
                        else:
                            # Use full tokens for complete response - NO REDUCTION
                            # All 6 sections are mandatory, do not compromise on completeness
                            
                            prompt = self.build_intelligent_prompt(question, context, has_kaanoon=True, question_analysis=question_analysis)
                            try:
                                llm_start = time.time()
                                # For ultra-fast queries, use lower temperature
                                response = self.client.chat.completions.create(
                                    model=self.model,
                                    messages=[{"role": "user", "content": prompt}],
                                    temperature=0.0,
                                    max_tokens=max_tokens
                                )
                                llm_time = time.time() - llm_start
                                
                                # Check if LLM exceeded budget
                                if llm_time > remaining_for_llm:
                                    print(f"[TIME ENFORCEMENT] LLM took {llm_time:.2f}s (remaining: {remaining_for_llm:.2f}s)")
                                
                                print(f"[LLM] Generation took {llm_time:.2f}s (budget: {llm_time_budget:.2f}s)")
                                answer = response.choices[0].message.content.strip()
                                extraction_method = 'llm_generated'
                            except Exception as e:
                                # Fallback: extract from Kaanoon Q&A document directly if API fails
                                if kaanoon_docs:
                                    print(f"[WARNING] API call failed: {e}, extracting from Kaanoon Q&A directly")
                                    answer = self.extract_answer_from_kaanoon_qa(kaanoon_docs[0])
                                    if not answer or len(answer) < 50:
                                        answer = context[:2000] if context else "I found relevant information but couldn't generate a complete answer. Please try rephrasing your question."
                                else:
                                    answer = context[:2000] if context else "I found relevant information but couldn't generate a complete answer. Please try rephrasing your question."
                                print(f"[WARNING] API call failed: {e}, using fallback")
                                extraction_method = 'context_fallback'
                else:
                    # No Kaanoon Q&A, use intelligent LLM generation
                    # Adjust tokens based on complexity and question analysis
                    word_count = len(question.split())
                    use_ultra_fast = is_simple_query and word_count <= 5
                    
                    # PROFESSIONAL FORMAT REQUIRES MAXIMUM TOKENS FOR ALL 6 SECTIONS:
                    # Answer + Opponent Analysis + Analysis (Key Principle + SILVER BULLET + #1 PRIORITY + STEP 1-4 + Remedies) + Legal Basis + Summary + Conclusion = 6000 tokens
                    if question_analysis.get('question_type') == 'multi_part':
                        max_tokens = 6000  # Multi-part: comprehensive with all mandatory sections
                    elif question_analysis.get('requires_procedure'):
                        max_tokens = 6000  # Procedural: detailed steps + all sections
                    elif use_ultra_fast:
                        max_tokens = 6000  # Ultra-fast: still need complete 6-section format
                    else:
                        max_tokens = 6000  # Professional format needs space for all 6 mandatory sections
                    # Check time before LLM call
                    elapsed_before_llm = time.time() - start_time
                    remaining_for_llm = max_time - elapsed_before_llm
                    
                    if remaining_for_llm < llm_time_budget * 0.3:
                        print(f"[TIME ENFORCEMENT] Insufficient time for LLM ({remaining_for_llm:.2f}s), using context fallback")
                        answer = context[:1500] if context else "I found relevant information but couldn't generate a complete answer within the time limit."
                        extraction_method = 'time_limit_fallback'
                    else:
                        # Use full tokens for complete response - NO REDUCTION
                        # All 6 sections are mandatory, do not compromise on completeness
                        
                        prompt = self.build_intelligent_prompt(question, context, has_kaanoon=False, question_analysis=question_analysis)
                        try:
                            llm_start = time.time()
                            # For ultra-fast queries, use lower temperature
                            response = self.client.chat.completions.create(
                                model=self.model,
                                messages=[{"role": "user", "content": prompt}],
                                temperature=0.05 if use_ultra_fast else 0.1,
                                max_tokens=max_tokens
                            )
                            llm_time = time.time() - llm_start
                            
                            # Check if LLM exceeded budget
                            if llm_time > remaining_for_llm:
                                print(f"[TIME ENFORCEMENT] LLM took {llm_time:.2f}s (remaining: {remaining_for_llm:.2f}s)")
                            
                            print(f"[LLM] Generation took {llm_time:.2f}s (budget: {llm_time_budget:.2f}s)")
                            answer = response.choices[0].message.content.strip()
                            extraction_method = 'llm_generated'
                        except Exception as e:
                            # Fallback: use full context if API fails (not truncated)
                            answer = context if context else "I found relevant information but couldn't generate a complete answer. Please try rephrasing your question."
                            print(f"[WARNING] API call failed: {e}, using fallback")
                            extraction_method = 'context_fallback'
            
            # Extract sources (limit for simple queries)
            max_sources = 3 if is_simple_query else 5
            sources = []
            for i, result in enumerate(results[:max_sources], 1):
                metadata = result.get('metadata', {})
                score = result.get('rerank_score', result.get('rrf_score', 0))
                sources.append({
                    'rank': i,
                    'score': float(score),
                    'source': metadata.get('source', 'Unknown'),
                    'category': metadata.get('category', 'Unknown'),
                    'is_kaanoon': metadata.get('source') == 'kaanoon_qa'
                })
            
            # Try to extract retrieved Q&A ID
            retrieved_id = None
            if kaanoon_docs:
                retrieved_id = kaanoon_docs[0].get('metadata', {}).get('qa_id')
            
            # Calculate final latency and verify time limit
            total_latency = time.time() - start_time
            
            # STRICT ENFORCEMENT: If exceeded time limit significantly, add warning to answer
            if total_latency > max_time * 1.1:  # 10% over limit
                complexity_status = "EXCEEDED LIMIT"
                if 'time_exceeded' not in locals():
                    answer = answer + "\n\n[Note: Response took longer than expected. For faster results, try simplifying your question.]"
            elif total_latency > max_time:
                complexity_status = "SLIGHTLY EXCEEDED"
            else:
                complexity_status = "WITHIN LIMIT"
            
            print(f"[TIMING] Total: {total_latency:.2f}s / {max_time}s target ({complexity_level.upper()}) - {complexity_status}")
            
            # Format answer with structure (title, bullets, sections)
            formatted_answer = self.format_structured_answer(
                answer,
                question,
                target_language=target_language,
            )
            
            # Validate response with LRE
            if self.reasoning_engine:
                validation = self.reasoning_engine.validate_response(formatted_answer)
                if not validation['valid']:
                    print(f"[LRE] Validation Warning: {validation['issues']}")
            
            # Generate title for the response
            response_title = self.generate_query_title(question, formatted_answer)
            
            # Store in conversation memory for follow-up questions
            if session_id:
                if session_id not in self.conversation_memory:
                    self.conversation_memory[session_id] = []
                # Extract topic from question or first line of answer for context
                topic = question if len(question) < 100 else question[:97] + "..."
                # Store question and FULL answer (up to 1000 chars) for short summaries
                self.conversation_memory[session_id].append((question, formatted_answer[:1000], topic))
                # Keep only last 5 exchanges
                if len(self.conversation_memory[session_id]) > 5:
                    self.conversation_memory[session_id] = self.conversation_memory[session_id][-5:]
            
            # ===== ENHANCEMENT: TIMELINE EXTRACTION & PRIMARY DOCUMENTS =====
            timeline_data = None
            primary_documents = []
            
            # Detect response type for timeline extraction
            try:
                detected_response_type = self.detect_query_response_type(question)
            except:
                detected_response_type = 'legal_advice'  # fallback
            
            # Extract timeline for educational responses
            if detected_response_type == 'educational' and self.timeline_builder:
                try:
                    # Build timeline from LLM response
                    timeline_data = self.timeline_builder.build_timeline_from_text(formatted_answer)
                    print(f"[TIMELINE] Extracted {len(timeline_data)} events from response")
                except Exception as e:
                    print(f"[WARNING] Timeline extraction failed: {e}")
            
            # TODO: Primary document extraction needs to be implemented earlier in retrieval flow
            # when retrieved_docs variable is actually available in scope
            
            return {
                'answer': formatted_answer,
                'title': response_title,  # Add generated title
                'context': context[:1000] if context else None,  # Truncate context for response
                'retrieved_id': retrieved_id,
                'sources': sources,
                'timeline': timeline_data,  # NEW: Structured timeline
                'primary_documents': primary_documents,  # NEW: Direct links to judgments
                'latency': total_latency,
                'used_kaanoon': has_kaanoon,
                'extraction_method': extraction_method,
                'detected_language': detected_lang,
                'complexity': complexity_info['complexity'],
                'complexity_score': complexity_info['score'],
                'target_max_time': max_time,
                'time_status': complexity_status
            }
            
        except Exception as e:
            print(f"[ERROR] {e}")
            import traceback
            traceback.print_exc()
            return {
                'answer': f"Error: {str(e)}",
                'context': None,
                'retrieved_id': None,
                'sources': [],
                'error': str(e)
            }


def test_adapter():
    """Test the ultimate RAG adapter"""
    print("\n" + "="*80)
    print("TESTING ULTIMATE RAG SYSTEM")
    print("="*80)
    
    adapter = UltimateRAGAdapter()
    
    test_queries = [
        "Can principal claim money after 25 years from property sale?",
        "What is the sequence of cross-examination in civil suits?",
        "Can divorced mother omit father's name from child's mark sheet?",
        "What is the latest status of the Electoral Bonds case 2024?"
    ]
    
    for query in test_queries:
        print(f"\n{'='*80}")
        print(f"Query: {query}")
        print('='*80)
        
        result = adapter.query(query)
        
        print(f"\nAnswer ({len(result['answer'])} chars):")
        print(result['answer'])
        print(f"\nMetadata:")
        print(f"  Retrieved ID: {result.get('retrieved_id')}")
        print(f"  Used Kaanoon: {result.get('used_kaanoon')}")
        print(f"  Extraction: {result.get('extraction_method')}")
        print(f"  Sources: {len(result.get('sources', []))}")
        print(f"  Latency: {result.get('latency', 0):.2f}s")


if __name__ == "__main__":
    test_adapter()

