"""
File creation tool supporting multiple formats
"""

from langchain_core.tools import tool
from typing import Dict, Any


# Import global state from parent module
def _get_global_state():
    """Get global state from parent module"""
    from livebench.tools.direct_tools import _global_state
    return _global_state


@tool
def create_file(filename: str, content: str, file_type: str = "txt") -> Dict[str, Any]:
    """
    Create a file in the sandboxed work directory.

    Supports multiple formats: txt, md, csv, json, xlsx, docx, pdf

    Args:
        filename: Name for the file (without extension)
        content: Content to write (format depends on file_type)
        file_type: File format - "txt", "md", "csv", "json", "xlsx", "docx", or "pdf"

    Returns:
        Dictionary with file creation result and path
    """
    import os
    import json as json_lib

    # Validate inputs
    if not filename or len(filename) < 1:
        return {"error": "Filename cannot be empty"}

    if not content or len(content) < 1:
        return {"error": "Content cannot be empty"}

    file_type = file_type.lower().strip()
    valid_types = ["txt", "md", "csv", "json", "xlsx", "docx", "pdf"]

    if file_type not in valid_types:
        return {
            "error": f"Invalid file type: {file_type}",
            "valid_types": valid_types
        }

    # Get sandbox directory
    _global_state = _get_global_state()
    data_path = _global_state.get("data_path")
    date = _global_state.get("current_date")

    if not data_path:
        return {"error": "Data path not configured"}

    # Create sandbox directory for file creation
    sandbox_dir = os.path.join(data_path, "sandbox", date or "default")
    os.makedirs(sandbox_dir, exist_ok=True)

    # Sanitize filename (remove path traversal attempts)
    safe_filename = os.path.basename(filename)
    safe_filename = safe_filename.replace('/', '_').replace('\\', '_')

    # Create full path
    file_path = os.path.join(sandbox_dir, f"{safe_filename}.{file_type}")

    try:
        # Handle different file types
        if file_type in ["txt", "md", "csv"]:
            # Plain text files
            with open(file_path, "w", encoding="utf-8") as f:
                f.write(content)

        elif file_type == "json":
            # JSON files - validate JSON
            try:
                json_data = json_lib.loads(content)
                with open(file_path, "w", encoding="utf-8") as f:
                    json_lib.dump(json_data, f, indent=2, ensure_ascii=False)
            except json_lib.JSONDecodeError as e:
                return {"error": f"Invalid JSON content: {str(e)}"}

        elif file_type == "xlsx":
            # Excel files - requires openpyxl
            try:
                import pandas as pd
                # Assume content is CSV-like or JSON
                try:
                    # Try parsing as JSON for structured data
                    data = json_lib.loads(content)
                    df = pd.DataFrame(data)
                except:
                    # Fall back to CSV parsing
                    import io
                    df = pd.read_csv(io.StringIO(content))

                df.to_excel(file_path, index=False, engine='openpyxl')
            except ImportError:
                return {"error": "openpyxl not installed. Run: pip install openpyxl pandas"}
            except Exception as e:
                return {"error": f"Failed to create Excel file: {str(e)}"}

        elif file_type == "docx":
            # Word documents - requires python-docx
            try:
                from docx import Document
                doc = Document()

                # Split content by paragraphs
                paragraphs = content.split('\n\n')
                for para in paragraphs:
                    if para.strip():
                        doc.add_paragraph(para.strip())

                doc.save(file_path)
            except ImportError:
                return {"error": "python-docx not installed. Run: pip install python-docx"}
            except Exception as e:
                return {"error": f"Failed to create Word document: {str(e)}"}

        elif file_type == "pdf":
            # PDF files - requires reportlab
            try:
                from reportlab.lib.pagesizes import letter
                from reportlab.platypus import SimpleDocTemplate, Paragraph, Spacer
                from reportlab.lib.styles import getSampleStyleSheet

                doc = SimpleDocTemplate(file_path, pagesize=letter)
                styles = getSampleStyleSheet()
                story = []

                # Split content by paragraphs
                paragraphs = content.split('\n\n')
                for para in paragraphs:
                    if para.strip():
                        story.append(Paragraph(para.strip(), styles['Normal']))
                        story.append(Spacer(1, 12))

                doc.build(story)
            except ImportError:
                return {"error": "reportlab not installed. Run: pip install reportlab"}
            except Exception as e:
                return {"error": f"Failed to create PDF: {str(e)}"}

        # Get file size
        file_size = os.path.getsize(file_path)

        return {
            "success": True,
            "filename": f"{safe_filename}.{file_type}",
            "file_path": file_path,
            "file_type": file_type,
            "file_size": file_size,
            "message": f"✅ Created {file_type.upper()} file: {safe_filename}.{file_type} ({file_size} bytes)\n\n⚠️ IMPORTANT: To submit this file as your work artifact, you MUST:\n1. Collect the file_path from this result: {file_path}\n2. Call submit_work(artifact_file_paths=[\"{file_path}\"]) or\n3. If creating multiple files, collect all paths and submit together:\n   submit_work(artifact_file_paths=[\"path1\", \"path2\", ...])"
        }

    except Exception as e:
        return {
            "error": f"Failed to create file: {str(e)}",
            "filename": safe_filename
        }
