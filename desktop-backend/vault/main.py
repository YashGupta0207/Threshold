from datetime import datetime, timezone, timedelta
import asyncio
import base64
import json
import logging
import os
import re
import secrets
import tempfile
import threading
import traceback
import uuid
from email.mime.text import MIMEText
from email.mime.multipart import MIMEMultipart
from typing import Dict, List

import bcrypt
import jwt
import httpx
from fastapi import Depends, FastAPI, File, Form, HTTPException, UploadFile
from fastapi.middleware.cors import CORSMiddleware
from fastapi.security import HTTPAuthorizationCredentials, HTTPBearer
from pydantic import BaseModel, EmailStr
from azure.cosmos import CosmosClient
from dotenv import load_dotenv

load_dotenv()

# Provider secrets come from the AI Gateway when DXAI_API_KEY is set, and fall
# back to .env otherwise. Imported after load_dotenv() so the module sees the
# gateway config, and before the constants below because it resolves them.
from gateway_credentials import secret, source_of  # noqa: E402

SECRET_KEY = os.getenv("JWT_SECRET", "threadnotes-super-secret-key")
ALGORITHM = "HS256"
AZURE_SPEECH_KEY = secret("AZURE_SPEECH_KEY").strip()
AZURE_SPEECH_REGION = secret("AZURE_SPEECH_REGION").strip()

COSMOS_ENDPOINT = secret("COSMOS_ENDPOINT")
COSMOS_KEY = secret("COSMOS_KEY")
DATABASE_NAME = secret("COSMOS_DATABASE")
USERS_CONTAINER = secret("COSMOS_USERS_CONTAINER", "users")

ADMIN_EMAIL = os.getenv("ADMIN_EMAIL", "").strip()
ADMIN_PASSWORD = os.getenv("ADMIN_PASSWORD", "")

app = FastAPI(
    title="ThreadNotes Cloud Vault",
    description="Lightweight secure vault for Auth + Azure Speech SDK tokens.",
    version="1.1.0",
)

app.add_middleware(
    CORSMiddleware,
    allow_origins=["*"],
    allow_credentials=True,
    allow_methods=["*"],
    allow_headers=["*"],
)

logging.basicConfig(level=logging.INFO)
_env_log = logging.getLogger("threadnotes.env")


@app.on_event("startup")
def _diagnose_env():
    """Log presence + length of critical env vars and the presence/size of the
    Gmail secret files at startup. Never logs the actual secret values or file
    contents — only whether they're set/exist and how large they are."""
    for key in (
        "GMAIL_SENDER",
        "BREVO_API_KEY",
        "JWT_SECRET",
        "COSMOS_ENDPOINT",
        "COSMOS_KEY",
        "COSMOS_DATABASE",
        "AZURE_SPEECH_KEY",
        "AZURE_SPEECH_REGION",
    ):
        # secret() rather than os.getenv() so a value supplied by the gateway
        # doesn't report present=False and send you hunting through .env.
        val = secret(key)
        _env_log.info(
            "ENV %-20s present=%-5s length=%-4s source=%s",
            key,
            bool(val),
            len(val) if val else 0,
            source_of(key),
        )

    for label, path in (
        ("credentials.json", GMAIL_CREDENTIALS_PATH),
        ("token.json", GMAIL_TOKEN_PATH),
    ):
        exists = os.path.exists(path)
        size = os.path.getsize(path) if exists else 0
        _env_log.info(
            "FILE %-16s path=%s exists=%-5s bytes=%s",
            label,
            path,
            exists,
            size,
        )


security = HTTPBearer(auto_error=True)

otp_storage: Dict[str, dict] = {}
signup_otp_storage: Dict[str, dict] = {}
verified_emails: Dict[str, datetime] = {}

_users_cont = None


def cosmos_config() -> tuple[str, str, str]:
    """Cosmos endpoint/key/database, re-read at call time.

    The module-level constants are resolved once at import. If the gateway was
    cold during that import they were bound to empty strings and would stay
    empty for the life of the process, even after gateway_credentials
    successfully retried. Reading through secret() here lets the vault recover
    on its own instead of needing a manual restart.
    """
    endpoint = COSMOS_ENDPOINT or secret("COSMOS_ENDPOINT")
    key = COSMOS_KEY or secret("COSMOS_KEY")
    database = DATABASE_NAME or secret("COSMOS_DATABASE")
    if not endpoint or not key or not database:
        raise HTTPException(
            status_code=503,
            detail="The vault is still fetching its credentials. Please try again in a moment.",
        )
    return endpoint, key, database


def get_users_container():
    global _users_cont
    if _users_cont is None:
        endpoint, key, database_name = cosmos_config()
        client = CosmosClient(endpoint, key)
        database = client.get_database_client(database_name)
        _users_cont = database.get_container_client(
            USERS_CONTAINER or secret("COSMOS_USERS_CONTAINER", "users")
        )
    return _users_cont


def build_openai_client(force_direct: bool = False):
    """Azure OpenAI client — through the gateway proxy, or straight to Azure.

    force_direct skips the proxy no matter what GATEWAY_PROXY_AI says. It
    exists for the fallback in _proxy_or_direct(): metering must never be able
    to take transcription down.

    Proxy mode (GATEWAY_PROXY_AI=true) routes calls via the gateway so they are
    metered: request counts and token usage show up against the developer token.
    Direct mode keeps the old behaviour and is the fallback when the token's
    request quota is exhausted.

    The plain OpenAI client is used for proxy mode rather than AzureOpenAI,
    because AzureOpenAI rewrites the path to
    /openai/deployments/{deployment}/... which the gateway does not serve. The
    plain client posts to {base_url}/audio/transcriptions, which lines up with
    the gateway's route once base_url ends in /gateway.

    The per-call deployment still travels in the multipart `model` field, which
    the gateway's Azure adapter reads to pick the deployment — so transcription
    and diarization can use different deployments over one client.
    """
    from openai import OpenAI, AzureOpenAI

    if not force_direct and os.getenv("GATEWAY_PROXY_AI", "").strip().lower() in (
        "1",
        "true",
        "yes",
    ):
        gw_token = os.getenv("DXAI_API_KEY", "").strip()
        gw_base = (os.getenv("DXAI_BASE_URL") or "").strip().rstrip("/")
        if not gw_token or not gw_base:
            raise HTTPException(
                status_code=500,
                detail="GATEWAY_PROXY_AI is on but DXAI_API_KEY/DXAI_BASE_URL are unset.",
            )
        return OpenAI(
            api_key=gw_token,
            base_url=f"{gw_base}/gateway",
            default_headers={
                "X-Gateway-Provider": os.getenv("GATEWAY_AI_PROVIDER", "AzureOpenAI"),
                # gpt-4o-transcribe is not served on the gateway's 2024-06-01
                # default, so pin the version this deployment needs.
                "X-Gateway-Api-Version": secret(
                    "AZURE_OPENAI_API_VERSION", "2025-04-01-preview"
                ).strip(),
            },
            timeout=1500,
            max_retries=0,
        )

    endpoint = secret("AZURE_OPENAI_ENDPOINT").strip()
    key = (secret("AZURE_OPENAI_KEY") or secret("OPENAI_API_KEY")).strip()
    if not key:
        raise HTTPException(status_code=500, detail="OpenAI/Azure OpenAI key is missing in the vault.")
    if endpoint:
        return AzureOpenAI(
            api_key=key,
            api_version=secret("AZURE_OPENAI_API_VERSION", "2025-04-01-preview").strip(),
            azure_endpoint=endpoint,
            timeout=1500,
            max_retries=0,
        )
    return OpenAI(api_key=key, timeout=1500, max_retries=0)


def interpolate_words(text: str, start: float, end: float) -> list:
    words = text.split()
    if not words:
        return []
    weights = [len(w) + 1 + (5 if w.endswith((".", "?", "!", ",", ";", "-")) else 0) for w in words]
    total = sum(weights) or 1
    duration = max(0.0, end - start)
    out, cursor = [], start
    for w, weight in zip(words, weights):
        cursor_end = cursor + duration * (weight / total)
        out.append({"word": w, "start": round(cursor, 3), "end": round(min(end, cursor_end), 3)})
        cursor = cursor_end
    if out:
        out[-1]["end"] = round(end, 3)
    return out


class UserSignup(BaseModel):
    name: str
    email: EmailStr
    password: str


class UserLogin(BaseModel):
    email: EmailStr
    password: str


class OTPRequest(BaseModel):
    email: EmailStr


class OTPVerifyRequest(BaseModel):
    email: EmailStr
    otp: str


class ForgotPasswordRequest(BaseModel):
    email: EmailStr


class ResetPasswordRequest(BaseModel):
    email: EmailStr
    otp: str
    new_password: str


class DeleteAccountRequest(BaseModel):
    confirm_password: str


class AdminLogin(BaseModel):
    email: str
    password: str


OTP_TTL = timedelta(minutes=5)
VERIFIED_TTL = timedelta(minutes=10)


def _generate_otp() -> str:
    """Cryptographically secure 6-digit OTP (000000–999999)."""
    return f"{secrets.randbelow(10**6):06d}"


GMAIL_SCOPES = ["https://www.googleapis.com/auth/gmail.send"]
_BACKEND_DIR = os.path.abspath(os.path.join(os.path.dirname(__file__), ".."))
GMAIL_CREDENTIALS_PATH = os.getenv(
    "GMAIL_CREDENTIALS_PATH", os.path.join(_BACKEND_DIR, "credentials.json")
)
GMAIL_TOKEN_PATH = os.getenv(
    "GMAIL_TOKEN_PATH", os.path.join(_BACKEND_DIR, "token.json")
)
_gmail_service = None

BREVO_API_KEY = os.getenv("BREVO_API_KEY", "").strip()
BREVO_API_URL = "https://api.brevo.com/v3/smtp/email"
BREVO_SENDER_NAME = os.getenv("BREVO_SENDER_NAME", "ThreadNotes").strip()
# Brevo only accepts a From address verified in its dashboard, which need not be
# the Gmail API sender. Falls back to GMAIL_SENDER when they are the same address.
BREVO_SENDER_EMAIL = os.getenv(
    "BREVO_SENDER_EMAIL", os.getenv("GMAIL_SENDER", "")
).strip()


def _build_gmail_service():
    """Build an authenticated Gmail API client from on-disk OAuth secret files.

    Loads the authorized-user token from token.json (which carries the refresh
    token + client id/secret minted once via the OAuth consent flow). Refreshes
    silently in-memory when the access token is expired. We never write the
    refreshed token back — on Render the secret files are read-only, and the
    in-memory refresh is enough. No interactive/browser flow on the server.
    Imports are lazy so a missing google lib can't crash app startup.

    Aggressive logging: any failure (FileNotFoundError, RefreshError from an
    expired/revoked token, etc.) is printed with a full traceback to the server
    logs before an HTTPException is raised, so the real cause is visible.
    """
    try:
        print(f"[GMAIL] building service — token path: {GMAIL_TOKEN_PATH}")
        if not os.path.exists(GMAIL_TOKEN_PATH):
            raise HTTPException(
                status_code=500,
                detail=f"Secret file not found at {GMAIL_TOKEN_PATH}",
            )

        from google.oauth2.credentials import Credentials
        from google.auth.transport.requests import Request
        from googleapiclient.discovery import build

        creds = Credentials.from_authorized_user_file(GMAIL_TOKEN_PATH, GMAIL_SCOPES)

        if not creds.valid:
            if creds.expired and creds.refresh_token:
                print("[GMAIL] access token expired — refreshing via refresh_token")
                creds.refresh(Request())
            else:
                raise HTTPException(
                    status_code=500,
                    detail="Gmail credentials are invalid and cannot be refreshed. "
                    "Regenerate token.json and re-upload it as a Render secret file.",
                )

        service = build("gmail", "v1", credentials=creds, cache_discovery=False)
        print("[GMAIL] service built successfully")
        return service
    except Exception as e:
        traceback.print_exc()
        print(f"CRITICAL GMAIL ERROR: {repr(e)}")
        if isinstance(e, HTTPException):
            raise
        raise HTTPException(
            status_code=500, detail=f"Gmail service initialization failed: {repr(e)}"
        )


def _get_gmail_service():
    """Cache the Gmail client; google-auth auto-refreshes the token on expiry."""
    global _gmail_service
    if _gmail_service is None:
        _gmail_service = _build_gmail_service()
    return _gmail_service


def _send_otp_via_brevo(target_email: str, otp: str, subject_prefix: str):
    """Send the OTP through Brevo's transactional API.

    The sender address must be verified in the Brevo dashboard (Senders,
    Domains & Dedicated IPs) or the API rejects the send with a 400.
    """
    if not BREVO_SENDER_EMAIL:
        raise HTTPException(
            status_code=500,
            detail="BREVO_SENDER_EMAIL must be set to a Brevo-verified sender address.",
        )

    payload = {
        "sender": {"name": BREVO_SENDER_NAME, "email": BREVO_SENDER_EMAIL},
        "to": [{"email": target_email}],
        "subject": f"ThreadNotes - {subject_prefix} OTP",
        "textContent": (
            f"Your OTP for {subject_prefix} is: {otp}\n\n"
            "Please do not share this with anyone."
        ),
    }

    try:
        resp = httpx.post(
            BREVO_API_URL,
            json=payload,
            headers={"api-key": BREVO_API_KEY, "accept": "application/json"},
            timeout=15.0,
        )
    except httpx.RequestError as e:
        print(f"CRITICAL BREVO ERROR: {repr(e)}")
        raise HTTPException(status_code=502, detail=f"Could not reach Brevo: {e}")

    if resp.status_code >= 400:
        print(f"CRITICAL BREVO ERROR: HTTP {resp.status_code} — {resp.text}")
        raise HTTPException(
            status_code=502,
            detail=f"Brevo rejected the send (HTTP {resp.status_code}): {resp.text}",
        )

    print(f"[BREVO] OTP email sent to {target_email} — {resp.json()}")


def send_otp_email(target_email: str, otp: str, subject_prefix: str):
    if BREVO_API_KEY:
        return _send_otp_via_brevo(target_email, otp, subject_prefix)

    try:
        service = _get_gmail_service()

        msg = MIMEMultipart()
        sender = os.getenv("GMAIL_SENDER")
        if sender:
            msg["From"] = sender
        msg["To"] = target_email
        msg["Subject"] = f"ThreadNotes - {subject_prefix} OTP"
        body = f"Your OTP for {subject_prefix} is: {otp}\n\nPlease do not share this with anyone."
        msg.attach(MIMEText(body, "plain"))

        raw = base64.urlsafe_b64encode(msg.as_bytes()).decode()
        result = service.users().messages().send(
            userId="me", body={"raw": raw}
        ).execute()
        print(f"[GMAIL] OTP email sent to {target_email} — id={result.get('id')}")
    except Exception as e:
        traceback.print_exc()
        print(f"CRITICAL GMAIL ERROR: {repr(e)}")
        if isinstance(e, HTTPException):
            raise
        raise HTTPException(
            status_code=502, detail=f"Failed to send email via Gmail API: {repr(e)}"
        )


def get_current_user(
    creds: HTTPAuthorizationCredentials = Depends(security),
) -> dict:
    try:
        payload = jwt.decode(creds.credentials, SECRET_KEY, algorithms=[ALGORITHM])
        if not isinstance(payload, dict):
            raise HTTPException(status_code=401, detail="Invalid authentication token")
        return payload
    except jwt.ExpiredSignatureError:
        raise HTTPException(status_code=401, detail="Session expired")
    except jwt.PyJWTError:
        raise HTTPException(status_code=401, detail="Invalid authentication token")


@app.post("/send-signup-otp")
def send_signup_otp(req: OTPRequest):
    users_cont = get_users_container()
    exists = list(
        users_cont.query_items(
            "SELECT * FROM c WHERE c.email = @email",
            parameters=[{"name": "@email", "value": req.email}],
            enable_cross_partition_query=True,
        )
    )
    if exists:
        raise HTTPException(status_code=400, detail="Email already registered. Please log in.")

    otp = _generate_otp()
    signup_otp_storage[req.email] = {
        "otp": otp,
        "expires_at": datetime.now(timezone.utc) + OTP_TTL,
    }
    send_otp_email(req.email, otp, "Signup Verification")
    return {"status": "success", "message": "Verification OTP sent successfully."}


@app.post("/verify-signup-otp")
def verify_signup_otp(req: OTPVerifyRequest):
    entry = signup_otp_storage.get(req.email)
    if not entry or entry.get("otp") != req.otp:
        raise HTTPException(status_code=400, detail="Invalid verification OTP.")
    if datetime.now(timezone.utc) >= entry["expires_at"]:
        signup_otp_storage.pop(req.email, None)
        raise HTTPException(
            status_code=400,
            detail="Verification OTP has expired. Please request a new one.",
        )

    verified_emails[req.email] = datetime.now(timezone.utc) + VERIFIED_TTL
    signup_otp_storage.pop(req.email, None)
    return {"status": "success", "message": "Email verified successfully."}


@app.post("/signup")
def signup(user: UserSignup):
    verified_until = verified_emails.get(user.email)
    if not verified_until or datetime.now(timezone.utc) >= verified_until:
        verified_emails.pop(user.email, None)
        raise HTTPException(
            status_code=403,
            detail="Email not verified. Please verify your OTP first.",
        )

    users_cont = get_users_container()
    exists = list(
        users_cont.query_items(
            "SELECT * FROM c WHERE c.email = @email",
            parameters=[{"name": "@email", "value": user.email}],
            enable_cross_partition_query=True,
        )
    )
    if exists:
        raise HTTPException(status_code=400, detail="Email already registered")

    hashed_pw = bcrypt.hashpw(user.password.encode("utf-8"), bcrypt.gensalt()).decode("utf-8")
    user_doc = {
        "id": str(uuid.uuid4()),
        "tenantId": str(uuid.uuid4()),
        "name": user.name,
        "email": user.email,
        "password": hashed_pw,
        "createdAt": datetime.now(timezone.utc).isoformat(),
    }
    users_cont.create_item(user_doc)
    verified_emails.pop(user.email, None)
    signup_otp_storage.pop(user.email, None)
    return {"status": "success", "message": "Account created"}


@app.post("/login")
def login(user: UserLogin):
    users_cont = get_users_container()
    user_list = list(
        users_cont.query_items(
            "SELECT * FROM c WHERE c.email = @email",
            parameters=[{"name": "@email", "value": user.email}],
            enable_cross_partition_query=True,
        )
    )
    if not user_list or not bcrypt.checkpw(
        user.password.encode("utf-8"), user_list[0]["password"].encode("utf-8")
    ):
        raise HTTPException(status_code=401, detail="Invalid credentials")

    token_data = {
        "sub": user_list[0]["email"],
        "tenantId": user_list[0]["tenantId"],
        "exp": datetime.now(timezone.utc) + timedelta(days=30),
    }
    return {
        "access_token": jwt.encode(token_data, SECRET_KEY, algorithm=ALGORITHM),
        "token_type": "bearer",
        "name": user_list[0]["name"],
    }


@app.post("/forgot-password")
def forgot_password(req: ForgotPasswordRequest):
    users_cont = get_users_container()
    user_list = list(
        users_cont.query_items(
            "SELECT * FROM c WHERE c.email = @email",
            parameters=[{"name": "@email", "value": req.email}],
            enable_cross_partition_query=True,
        )
    )
    generic_response = {
        "status": "success",
        "message": "If an account exists for that email, a reset OTP has been sent.",
    }
    if not user_list:
        return generic_response

    otp = _generate_otp()
    otp_storage[req.email] = {
        "otp": otp,
        "expires_at": datetime.now(timezone.utc) + OTP_TTL,
    }
    send_otp_email(req.email, otp, "Password Reset")
    return generic_response


@app.post("/reset-password")
def reset_password(req: ResetPasswordRequest):
    entry = otp_storage.get(req.email)
    if not entry or entry.get("otp") != req.otp:
        raise HTTPException(status_code=400, detail="Invalid OTP.")
    if datetime.now(timezone.utc) >= entry["expires_at"]:
        otp_storage.pop(req.email, None)
        raise HTTPException(
            status_code=400, detail="OTP has expired. Please request a new one."
        )

    users_cont = get_users_container()
    user_list = list(
        users_cont.query_items(
            "SELECT * FROM c WHERE c.email = @email",
            parameters=[{"name": "@email", "value": req.email}],
            enable_cross_partition_query=True,
        )
    )
    if not user_list:
        raise HTTPException(status_code=404, detail="User not found")

    user_doc = user_list[0]
    user_doc["password"] = bcrypt.hashpw(
        req.new_password.encode("utf-8"), bcrypt.gensalt()
    ).decode("utf-8")
    users_cont.upsert_item(user_doc)
    otp_storage.pop(req.email, None)
    return {"status": "success", "message": "Password updated successfully!"}


def _delete_user_transcripts(user_id: str) -> int:
    """Best-effort cascade: remove any cloud transcripts owned by this user.

    Transcripts are now stored locally on the user's PC, so the cloud
    transcripts container typically does not exist. This stays defensive: if a
    transcripts container IS present (legacy data / forward-compat), it deletes
    every doc whose userId matches; if not, it returns 0 without failing the
    account deletion. We never create the container here.
    """
    if not (COSMOS_ENDPOINT and COSMOS_KEY and DATABASE_NAME):
        return 0
    try:
        client = CosmosClient(COSMOS_ENDPOINT, COSMOS_KEY)
        database = client.get_database_client(DATABASE_NAME)
        container = database.get_container_client(
            secret("COSMOS_TRANSCRIPTS_CONTAINER", "transcripts")
        )
        items = list(
            container.query_items(
                "SELECT c.id, c.userId FROM c WHERE c.userId = @uid",
                parameters=[{"name": "@uid", "value": user_id}],
                enable_cross_partition_query=True,
            )
        )
        deleted = 0
        for it in items:
            try:
                container.delete_item(
                    item=it["id"], partition_key=it.get("userId", user_id)
                )
                deleted += 1
            except Exception:
                pass
        return deleted
    except Exception:
        return 0


@app.delete("/delete-account")
def delete_account(
    req: DeleteAccountRequest,
    user: dict = Depends(get_current_user),
):
    email = user.get("sub")
    if not email:
        raise HTTPException(status_code=401, detail="Invalid authentication token")

    users_cont = get_users_container()
    user_list = list(
        users_cont.query_items(
            "SELECT * FROM c WHERE c.email = @email",
            parameters=[{"name": "@email", "value": email}],
            enable_cross_partition_query=True,
        )
    )
    if not user_list:
        raise HTTPException(status_code=404, detail="User not found")

    user_doc = user_list[0]

    stored_hash = (user_doc.get("password") or "").encode("utf-8")
    if not stored_hash or not bcrypt.checkpw(
        req.confirm_password.encode("utf-8"), stored_hash
    ):
        raise HTTPException(status_code=401, detail="Incorrect password.")

    deleted_transcripts = _delete_user_transcripts(email)

    try:
        props = users_cont.read()
        pk_path = (props.get("partitionKey", {}).get("paths") or ["/id"])[0]
        pk_value = user_doc.get(pk_path.strip("/"), user_doc.get("id"))
        users_cont.delete_item(item=user_doc["id"], partition_key=pk_value)
    except HTTPException:
        raise
    except Exception as exc:
        raise HTTPException(status_code=500, detail=f"Failed to delete account: {exc}")

    verified_emails.pop(email, None)
    otp_storage.pop(email, None)
    signup_otp_storage.pop(email, None)

    return {
        "status": "success",
        "message": "Account deleted.",
        "transcripts_deleted": deleted_transcripts,
    }


def get_current_admin(
    creds: HTTPAuthorizationCredentials = Depends(security),
) -> dict:
    try:
        payload = jwt.decode(creds.credentials, SECRET_KEY, algorithms=[ALGORITHM])
    except jwt.ExpiredSignatureError:
        raise HTTPException(status_code=401, detail="Session expired")
    except jwt.PyJWTError:
        raise HTTPException(status_code=401, detail="Invalid authentication token")
    if not isinstance(payload, dict) or payload.get("role") != "admin":
        raise HTTPException(status_code=403, detail="Admin access required")
    return payload


@app.post("/admin/login")
def admin_login(req: AdminLogin):
    if not ADMIN_EMAIL or not ADMIN_PASSWORD:
        raise HTTPException(
            status_code=500,
            detail="Admin login is not configured on the server.",
        )
    if (
        req.email.strip().lower() != ADMIN_EMAIL.lower()
        or req.password != ADMIN_PASSWORD
    ):
        raise HTTPException(status_code=401, detail="Invalid admin credentials")
    token_data = {
        "sub": ADMIN_EMAIL,
        "role": "admin",
        "exp": datetime.now(timezone.utc) + timedelta(hours=8),
    }
    return {
        "access_token": jwt.encode(token_data, SECRET_KEY, algorithm=ALGORITHM),
        "token_type": "bearer",
    }


@app.get("/admin/users")
def admin_list_users(admin: dict = Depends(get_current_admin)):
    users_cont = get_users_container()
    rows = list(
        users_cont.query_items(
            "SELECT c.id, c.name, c.email, c.createdAt FROM c",
            enable_cross_partition_query=True,
        )
    )
    rows.sort(key=lambda u: u.get("createdAt") or "", reverse=True)
    return {"status": "success", "users": rows, "count": len(rows)}


@app.delete("/admin/users/{user_id}")
def admin_delete_user(user_id: str, admin: dict = Depends(get_current_admin)):
    users_cont = get_users_container()
    user_list = list(
        users_cont.query_items(
            "SELECT * FROM c WHERE c.id = @id",
            parameters=[{"name": "@id", "value": user_id}],
            enable_cross_partition_query=True,
        )
    )
    if not user_list:
        raise HTTPException(status_code=404, detail="User not found")
    user_doc = user_list[0]
    email = user_doc.get("email")

    _delete_user_transcripts(email)

    try:
        props = users_cont.read()
        pk_path = (props.get("partitionKey", {}).get("paths") or ["/id"])[0]
        pk_value = user_doc.get(pk_path.strip("/"), user_doc.get("id"))
        users_cont.delete_item(item=user_doc["id"], partition_key=pk_value)
    except HTTPException:
        raise
    except Exception as exc:
        raise HTTPException(status_code=500, detail=f"Failed to delete user: {exc}")

    if email:
        verified_emails.pop(email, None)
        otp_storage.pop(email, None)
        signup_otp_storage.pop(email, None)

    return {"status": "success", "message": "User deleted."}


@app.get("/azure/token")
async def get_azure_speech_token(user: dict = Depends(get_current_user)):
    if not AZURE_SPEECH_KEY or not AZURE_SPEECH_REGION:
        raise HTTPException(status_code=500, detail="Azure Speech configuration is missing.")

    sts_url = f"https://{AZURE_SPEECH_REGION}.api.cognitive.microsoft.com/sts/v1.0/issueToken"

    try:
        async with httpx.AsyncClient(timeout=10) as client:
            response = await client.post(
                sts_url,
                headers={
                    "Ocp-Apim-Subscription-Key": AZURE_SPEECH_KEY,
                    "Content-Length": "0",
                },
            )
        response.raise_for_status()
    except Exception as exc:
        raise HTTPException(status_code=502, detail=f"Azure token request failed: {exc}")

    return {"token": response.text, "region": AZURE_SPEECH_REGION}


_NOISE_ANNOTATION = re.compile(
    r"^[\(\[\*]?\s*(breath|breathing|inhale|exhale|cough|sneeze|click|"
    r"clicks|noise|static|silence|music|laughter|laughs?|sigh)\s*[\)\]\*]?$",
    re.IGNORECASE,
)


def _is_noise_fragment(text: str) -> bool:
    """Heuristic: True for non-verbal noise that should not create a speaker.

    Catches (a) explicit non-verbal annotations like "(breath)" / "[cough]",
    and (b) fragments that carry no real characters — e.g. punctuation-only
    "...", "*" clicks, or "--". Uses Unicode-aware ``str.isalnum`` so genuine
    short words in any script (English "Hi"/"No", Hindi, etc.) pass through.
    """
    t = text.strip()
    if _NOISE_ANNOTATION.match(t):
        return True
    if not any(ch.isalnum() for ch in t):
        return True
    return False


def _create_diarized_transcription(client, deployment, safe_name, audio_bytes, mime):
    """Call the diarization model.

    NOTE: the gpt-4o-transcribe-diarize deployment REJECTS the `prompt`
    parameter (400 invalid_request_error), so we never send it — doing so only
    wasted a guaranteed-failed round-trip + an SDK retry on every single chunk.
    Speaker over-segmentation is instead handled downstream by the ghost-speaker
    filter (_merge_ghost_speakers / _identify_ghost_speakers), so dropping the
    prompt does NOT change the diarization output — it just removes the waste.
    """
    base = dict(
        model=deployment,
        file=(safe_name, audio_bytes, mime),
        response_format="diarized_json",
        extra_body={"chunking_strategy": "auto"},
    )
    try:
        return client.audio.transcriptions.create(**base)
    except Exception as exc:
        body = getattr(getattr(exc, "response", None), "text", None)
        status = getattr(getattr(exc, "response", None), "status_code", None)
        print(
            f"CRITICAL DIARIZE ERROR (status={status}): {exc}\n"
            f"Azure response body: {body}",
            flush=True,
        )
        traceback.print_exc()
        raise


def _friendly_diarize_error(exc: Exception) -> str:
    """Translate a raw transcription/diarization exception into a short, plain
    English sentence safe to show the end user — no stack traces, status codes,
    or SDK jargon. Used for BOTH live-recording and uploaded-file diarization
    (they share the /diarize/stream endpoint)."""
    status = getattr(getattr(exc, "response", None), "status_code", None)
    name = type(exc).__name__.lower()
    msg = str(exc).lower()

    if "timeout" in name or "timed out" in msg or status == 408:
        return (
            "This recording is too long to process in one go and timed out. "
            "Please try a shorter recording, or split it into smaller parts."
        )
    if "connection" in name or "connect" in msg:
        return (
            "We couldn't reach the transcription service. "
            "Please check your internet connection and try again."
        )
    # A 429 means two very different things, and the fixes are opposite: a
    # provider rate limit clears on its own in a minute, an exhausted gateway
    # quota never does without an admin raising the cap. "limit exceeded" is
    # the gateway's own wording (_enforce_limits) and only appears for quota,
    # so check it before the generic rate-limit branch below.
    # Matched on the gateway's four exact phrases rather than a loose
    # "limit exceeded", because Azure also says things like "rate limit
    # exceeded" — which is the opposite situation and must not land here.
    if any(
        f"{period} {unit} limit exceeded" in msg
        for period in ("daily", "monthly")
        for unit in ("request", "token")
    ):
        unit = "token" if "token limit exceeded" in msg else "request"
        if "daily" in msg:
            period, resets = "daily", " It resets tomorrow."
        elif "monthly" in msg:
            period, resets = "monthly", " It resets at the start of next month."
        else:
            period, resets = "", ""
        quota = f"{period} {unit}".strip()
        return (
            f"You have reached the limit — your {quota} quota has been used up."
            f"{resets} Please contact your administrator to increase it."
        )
    if status == 429 or "rate limit" in msg or "ratelimit" in name:
        return (
            "The transcription service is busy right now. "
            "Please wait a minute and try again."
        )
    if status in (401, 403) or "authentication" in name or "permission" in name:
        return (
            "The transcription service rejected our credentials. "
            "Please contact support — this is a configuration issue, not your file."
        )
    if status == 400 or "bad request" in msg or "invalid" in msg:
        if "duration" in msg or "1500" in msg or "too long" in msg:
            return (
                "This audio is too long for the transcription model. "
                "Please use a shorter recording or file."
            )
        return (
            "This audio couldn't be processed. It may be in an unsupported "
            "format or corrupted. Please try a different file."
        )
    return (
        "Something went wrong while transcribing this audio. "
        "Please try again in a moment."
    )


GHOST_MAX_WORDS = 3
GHOST_MAX_DURATION = 2.0
GHOST_RELATIVE_RATIO = 0.08


def _speaker_stats(segments: List[dict]) -> Dict[str, dict]:
    stats: Dict[str, dict] = {}
    for i, seg in enumerate(segments):
        sp = seg["speaker"]
        s = stats.setdefault(
            sp, {"words": 0, "duration": 0.0, "segments": 0, "first": i}
        )
        s["words"] += len(seg.get("words") or [])
        s["duration"] += max(0.0, float(seg["end"]) - float(seg["start"]))
        s["segments"] += 1
    return stats


def _identify_ghost_speakers(stats: Dict[str, dict]) -> set:
    if len(stats) <= 1:
        return set()
    max_words = max((s["words"] for s in stats.values()), default=0) or 1
    ghosts = set()
    for sp, s in stats.items():
        absolute_ghost = (
            s["words"] <= GHOST_MAX_WORDS and s["duration"] <= GHOST_MAX_DURATION
        )
        relative_ghost = (
            s["words"] < GHOST_RELATIVE_RATIO * max_words
            and s["duration"] <= GHOST_MAX_DURATION
        )
        if absolute_ghost or relative_ghost:
            ghosts.add(sp)
    if len(ghosts) >= len(stats):
        busiest = max(
            stats, key=lambda sp: (stats[sp]["words"], stats[sp]["duration"])
        )
        ghosts.discard(busiest)
    return ghosts


def _nearest_primary_label(segments: List[dict], idx: int, ghosts: set):
    """Speaker label of the temporally nearest non-ghost segment (prev wins ties)."""
    n = len(segments)
    for dist in range(1, n):
        before = idx - dist
        if before >= 0 and segments[before]["speaker"] not in ghosts:
            return segments[before]["speaker"]
        after = idx + dist
        if after < n and segments[after]["speaker"] not in ghosts:
            return segments[after]["speaker"]
    return None


def _merge_ghost_speakers(segments: List[dict]) -> List[dict]:
    """Reassign ghost-speaker segments to the nearest primary speaker, then
    coalesce consecutive same-speaker segments into single blocks.

    Word-level {word, start, end} entries are carried over VERBATIM (never
    recomputed or reordered), so frontend karaoke highlighting stays exact.
    """
    if len(segments) < 2:
        return segments

    ghosts = _identify_ghost_speakers(_speaker_stats(segments))
    if not ghosts:
        return segments

    for i, seg in enumerate(segments):
        if seg["speaker"] in ghosts:
            target = _nearest_primary_label(segments, i, ghosts)
            if target is not None:
                seg["speaker"] = target

    merged: List[dict] = []
    for seg in segments:
        if merged and merged[-1]["speaker"] == seg["speaker"]:
            prev = merged[-1]
            prev["text"] = f'{prev["text"]} {seg["text"]}'.strip()
            prev["words"] = (prev.get("words") or []) + (seg.get("words") or [])
            prev["start"] = round(min(float(prev["start"]), float(seg["start"])), 3)
            prev["end"] = round(max(float(prev["end"]), float(seg["end"])), 3)
        else:
            merged.append(dict(seg))
    return merged


def _renumber_speakers(segments: List[dict]) -> List[dict]:
    """Remap speaker labels to contiguous 'Speaker 1..N' by first appearance."""
    remap: Dict[str, str] = {}
    for seg in segments:
        sp = seg["speaker"]
        if sp not in remap:
            remap[sp] = f"Speaker {len(remap) + 1}"
        seg["speaker"] = remap[sp]
    return segments


def _run_diarization(audio_bytes: bytes, filename: str, content_type: str = "") -> list:
    deployment = secret("AZURE_DIARIZE_DEPLOYMENT", "gpt-4o-transcribe-diarize").strip()

    safe_name = filename or "audio.ogg"
    mime = content_type or "audio/ogg"

    resp = _proxy_or_direct(
        lambda client: _create_diarized_transcription(
            client, deployment, safe_name, audio_bytes, mime
        )
    )
    data = (
        resp.model_dump()
        if hasattr(resp, "model_dump")
        else (resp if isinstance(resp, dict) else json.loads(str(resp)))
    )

    speaker_map: Dict[str, str] = {}
    segments: List[dict] = []
    for seg in data.get("segments") or []:
        text = (seg.get("text") or "").strip()
        if not text:
            continue
        if _is_noise_fragment(text):
            continue
        raw = str(seg.get("speaker", "") or "").strip() or "unknown"
        if raw not in speaker_map:
            speaker_map[raw] = f"Speaker {len(speaker_map) + 1}"
        label = speaker_map[raw]
        start = float(seg.get("start", 0.0) or 0.0)
        end = float(seg.get("end", start) or start)
        raw_words = seg.get("words")
        if isinstance(raw_words, list) and raw_words:
            words = []
            for w in raw_words:
                token = str(w.get("word", w.get("text", "")) or "").strip()
                if not token:
                    continue
                w_start = float(w.get("start", start) or start)
                w_end = float(w.get("end", w_start) or w_start)
                words.append(
                    {
                        "word": token,
                        "start": round(w_start, 3),
                        "end": round(w_end, 3),
                    }
                )
            if not words:
                words = interpolate_words(text, start, end)
        else:
            words = interpolate_words(text, start, end)
        segments.append(
            {
                "type": "transcript",
                "text": f"{text}",
                "speaker": label,
                "start": round(start, 3),
                "end": round(end, 3),
                "words": words,
            }
        )

    # A recording with one speaker (or one with speech the model won't split)
    # comes back as text with an empty `segments` list. Returning [] there gives
    # the user an empty diarized view next to a perfectly good transcript, which
    # reads as a failure. Emit the whole chunk as Speaker 1 instead — the audio
    # really does have exactly one speaker.
    if not segments:
        whole = (data.get("text") or "").strip()
        if whole and not _is_noise_fragment(whole):
            duration = float(data.get("duration", 0.0) or 0.0)
            segments = [
                {
                    "type": "transcript",
                    "text": whole,
                    "speaker": "Speaker 1",
                    "start": 0.0,
                    "end": round(duration, 3),
                    "words": interpolate_words(whole, 0.0, duration),
                }
            ]
        return segments

    segments = _merge_ghost_speakers(segments)
    segments = _renumber_speakers(segments)
    return segments


@app.post("/diarize/stream")
async def diarize_stream(
    file: UploadFile = File(...),
    user: dict = Depends(get_current_user),
):
    audio_bytes = await file.read()
    if not audio_bytes:
        raise HTTPException(status_code=400, detail="Empty audio upload.")
    try:
        segments = await asyncio.to_thread(
            _run_diarization,
            audio_bytes,
            file.filename or "audio.ogg",
            file.content_type or "audio/ogg",
        )
    except HTTPException:
        raise
    except Exception as exc:
        traceback.print_exc()
        return {"status": "error", "message": _friendly_diarize_error(exc)}

    return {
        "status": "success",
        "segments": segments,
        "merged_transcript": segments,
    }


def _run_transcription(audio_bytes: bytes, filename: str, content_type: str = "") -> str:
    deployment = (
        secret("AZURE_TRANSCRIBE_DEPLOYMENT")
        or secret("AZURE_WHISPER_DEPLOYMENT")
        or "gpt-4o-transcribe"
    ).strip()
    safe_name = filename or "audio.ogg"
    mime = content_type or "audio/ogg"
    # "json" rather than "text": Azure only returns a `usage` block on the JSON
    # response, and without it the gateway has no token counts to record. The
    # transcript itself is identical — it just arrives as .text instead of a
    # bare string, which the return below already handles either way.
    resp = _proxy_or_direct(
        lambda client: client.audio.transcriptions.create(
            model=deployment,
            file=(safe_name, audio_bytes, mime),
            response_format="json",
        )
    )
    if isinstance(resp, str):
        return resp.strip()
    return (getattr(resp, "text", "") or str(resp)).strip()


@app.post("/transcribe/stream")
async def transcribe_stream(
    file: UploadFile = File(...),
    user: dict = Depends(get_current_user),
):
    audio_bytes = await file.read()
    if not audio_bytes:
        raise HTTPException(status_code=400, detail="Empty audio upload.")
    try:
        text = await asyncio.to_thread(
            _run_transcription,
            audio_bytes,
            file.filename or "audio.ogg",
            file.content_type or "audio/ogg",
        )
    except HTTPException:
        raise
    except Exception as exc:
        traceback.print_exc()
        return {"status": "error", "message": _friendly_diarize_error(exc)}

    return {"status": "success", "text": text}


# Roughly 15k tokens of transcript. Long meetings are trimmed head+tail rather
# than truncated, because the closing minutes usually carry the decisions and
# action items that make a summary worth reading.
SUMMARY_MAX_CHARS = 60000

SUMMARY_SYSTEM_PROMPT = (
    "You summarise meeting transcripts. Produce a clear, factual summary in "
    "markdown with these sections, omitting any section that has no content:\n\n"
    "## Overview\n"
    "Two or three sentences on what the meeting was about.\n\n"
    "## Key Points\n"
    "Bullet points of what was discussed.\n\n"
    "## Decisions\n"
    "Bullet points of what was actually decided.\n\n"
    "## Action Items\n"
    "Bullet points of who agreed to do what. Name the person when the "
    "transcript makes it clear, and do not invent an owner when it does not.\n\n"
    "Use only what the transcript supports and never invent details. If the "
    "transcript is too short or too garbled to summarise, say so plainly "
    "instead of padding."
)


GEMINI_API_URL = (
    "https://generativelanguage.googleapis.com/v1beta/models/{model}:generateContent"
)


def _summary_via_gateway(model: str, text: str) -> str | None:
    """Run the completion through the gateway so it can be metered.

    The gateway only writes an ApiRequestLog row on its proxy paths;
    /gateway/credentials just hands over keys and counts nothing. So a summary
    called straight at Google is invisible to the admin dashboard no matter how
    many are run. Going through /gateway/chat/completions is what makes
    requests, prompt/completion tokens and last-used appear.

    Returns None when the gateway itself is unreachable or broken, so the
    caller can still produce a summary directly. A 4xx is a real answer -- bad
    token, provider not authorised -- and is raised rather than silently
    bypassed, because falling back there would hide a misconfiguration forever.
    """
    token = os.getenv("DXAI_API_KEY", "").strip()
    base = (os.getenv("DXAI_BASE_URL") or "").strip().rstrip("/")
    if not token or not base:
        return None

    try:
        resp = httpx.post(
            f"{base}/gateway/chat/completions",
            headers={
                "Authorization": f"Bearer {token}",
                "X-Gateway-Provider": os.getenv("GATEWAY_SUMMARY_PROVIDER", "gemini"),
                "Content-Type": "application/json",
            },
            json={
                "model": model,
                # The gemini adapter maps this OpenAI shape onto
                # models/{model}:generateContent, folding "system" into the
                # first user turn since Gemini has no system role in contents.
                "messages": [
                    {"role": "system", "content": SUMMARY_SYSTEM_PROMPT},
                    {"role": "user", "content": text},
                ],
            },
            timeout=180.0,
        )
    except httpx.RequestError as exc:
        print(f"GATEWAY summary proxy unreachable, calling Gemini directly: {exc!r}")
        return None

    # A spent quota is fatal here too, for the same reason as audio: falling
    # back would mean the limit never actually limits anything.
    if resp.status_code == 429:
        print("GATEWAY summary quota reached: %s" % resp.text[:200])
        raise HTTPException(
            status_code=429,
            detail=_friendly_diarize_error(
                RuntimeError(resp.text or "daily token limit exceeded")
            ),
        )
    if resp.status_code >= 500:
        print(
            "GATEWAY summary proxy unreachable (HTTP %s), calling Gemini "
            "directly — this call will NOT be metered: %s"
            % (resp.status_code, resp.text[:200])
        )
        return None
    if resp.status_code >= 400:
        print(f"GATEWAY summary proxy rejected: {resp.status_code} {resp.text[:300]}")
        raise HTTPException(
            status_code=502,
            detail=(
                f"The AI gateway rejected the summary request "
                f"(HTTP {resp.status_code}). Check the token is authorised for "
                "the gemini provider."
            ),
        )

    try:
        data = resp.json()
    except ValueError:
        return None

    choices = data.get("choices") or []
    if not choices:
        return None
    content = ((choices[0].get("message") or {}).get("content") or "").strip()
    return content or None


def _proxy_or_direct(call):
    """Run an Azure call through the gateway, falling back to a direct call.

    Everything should be counted, but the gateway enforces per-token daily and
    monthly caps on its proxy paths, and audio transcription spends tokens fast
    enough to reach them. A 429 there would otherwise fail diarisation
    outright -- metering would be taking the product down.

    So the proxied attempt comes first, and only a quota rejection or a gateway
    fault drops to a direct call. Provider errors (bad audio, unsupported
    format) are raised untouched: retrying those directly would just repeat the
    same failure and hide where it came from.

    `call` takes the client and returns the provider response.
    """
    proxied = os.getenv("GATEWAY_PROXY_AI", "").strip().lower() in ("1", "true", "yes")
    if not proxied:
        return call(build_openai_client())

    try:
        return call(build_openai_client())
    except Exception as exc:
        status = getattr(exc, "status_code", None) or getattr(
            getattr(exc, "response", None), "status_code", None
        )
        body = str(getattr(exc, "message", "") or exc)

        # A spent quota is deliberately fatal. Falling back would keep the app
        # working while silently spending unmetered, which defeats having a
        # limit at all -- the caller turns this into the plain-English
        # "you have reached the limit" message via _friendly_diarize_error.
        if status == 429 or "limit exceeded" in body.lower():
            print("GATEWAY quota reached, refusing the call: %s" % body[:200])
            raise

        # A gateway outage is a different matter: it is not the user exceeding
        # anything, so the work still goes through, unmetered and logged.
        if status is not None and status >= 500:
            print(
                "GATEWAY unreachable (%s), retrying direct — this call will "
                "NOT be metered: %s" % (status, body[:200])
            )
            return call(build_openai_client(force_direct=True))
        raise


def _run_summary(transcript: str) -> str:
    """Summarise a transcript with Gemini.

    Azure OpenAI cannot do this job: the gateway's AzureOpenAI profile exposes
    only AZURE_TRANSCRIBE_DEPLOYMENT and AZURE_DIARIZE_DEPLOYMENT, both audio
    models with no chat capability. The gateway's `gemini` profile carries the
    key, under the variable name `api_key` -- so "gemini" must appear in
    GATEWAY_PROVIDERS or the key never reaches this process.
    """
    key = (secret("GEMINI_API_KEY") or secret("api_key")).strip()
    if not key:
        raise HTTPException(
            status_code=500,
            detail=(
                "No Gemini API key available. Add 'gemini' to GATEWAY_PROVIDERS "
                "so the vault fetches it at startup, or set GEMINI_API_KEY."
            ),
        )
    model = secret("GEMINI_SUMMARY_MODEL", "gemini-3.6-flash").strip()

    text = transcript.strip()
    if len(text) > SUMMARY_MAX_CHARS:
        half = SUMMARY_MAX_CHARS // 2
        text = (
            text[:half]
            + "\n\n[... middle of the transcript omitted for length ...]\n\n"
            + text[-half:]
        )

    # Summaries proxy on their own switch, separate from audio. Audio
    # transcription burns enough tokens to trip the gateway's daily cap in a
    # handful of calls, and a 429 there blocks diarisation outright; summaries
    # are small and infrequent, so they can stay metered without that risk.
    _proxy_summary = os.getenv("GATEWAY_PROXY_SUMMARY", "").strip().lower()
    if not _proxy_summary:
        _proxy_summary = os.getenv("GATEWAY_PROXY_AI", "").strip().lower()
    if _proxy_summary in ("1", "true", "yes"):
        proxied = _summary_via_gateway(model, text)
        if proxied:
            return proxied

    payload = {
        "systemInstruction": {"parts": [{"text": SUMMARY_SYSTEM_PROMPT}]},
        "contents": [{"role": "user", "parts": [{"text": text}]}],
        "generationConfig": {"temperature": 0.2},
    }

    try:
        # The key goes in a header, NOT the ?key= query parameter Google also
        # accepts. httpx logs the full request URL at INFO level and Render
        # captures stdout, so a query-string key would be printed into the
        # production logs on every single summary request.
        resp = httpx.post(
            GEMINI_API_URL.format(model=model),
            headers={"x-goog-api-key": key},
            json=payload,
            timeout=180.0,
        )
    except httpx.RequestError as exc:
        print(f"CRITICAL GEMINI ERROR: {exc!r}")
        raise HTTPException(status_code=502, detail=f"Could not reach Gemini: {exc}")

    if resp.status_code >= 400:
        # The body names the real cause (retired model, bad key, quota), so log
        # it, but do not hand the raw provider text to the client.
        print(f"CRITICAL GEMINI ERROR: HTTP {resp.status_code} - {resp.text[:400]}")
        if resp.status_code == 404:
            raise HTTPException(
                status_code=502,
                detail=(
                    f"Gemini model '{model}' is unavailable to this key. Set "
                    "GEMINI_SUMMARY_MODEL to a model the key can use."
                ),
            )
        raise HTTPException(
            status_code=502,
            detail=f"Gemini rejected the request (HTTP {resp.status_code}).",
        )

    data = resp.json()
    candidates = data.get("candidates") or []
    if not candidates:
        blocked = (data.get("promptFeedback") or {}).get("blockReason")
        raise HTTPException(
            status_code=502,
            detail=(
                f"Gemini returned no summary (blocked: {blocked})."
                if blocked
                else "Gemini returned no summary."
            ),
        )

    cand = candidates[0]
    parts = (cand.get("content") or {}).get("parts") or []
    out = "".join(p.get("text", "") for p in parts).strip()
    if not out:
        reason = cand.get("finishReason") or "unknown"
        raise HTTPException(
            status_code=502,
            detail=f"Gemini returned an empty summary (finishReason: {reason}).",
        )
    return out


class SummarizeRequest(BaseModel):
    text: str
    meeting_id: str = ""


@app.post("/summarize")
async def summarize(
    req: SummarizeRequest,
    user: dict = Depends(get_current_user),
):
    """Summarise a transcript. Takes the plain or the speaker-labelled text."""
    text = (req.text or "").strip()
    if not text:
        raise HTTPException(
            status_code=400, detail="There is no transcript to summarise."
        )
    if len(text) < 40:
        raise HTTPException(
            status_code=400, detail="This transcript is too short to summarise."
        )
    try:
        summary = await asyncio.to_thread(_run_summary, text)
    except HTTPException:
        raise
    except Exception as exc:
        traceback.print_exc()
        return {"status": "error", "message": _friendly_diarize_error(exc)}

    if not summary:
        return {"status": "error", "message": "The model returned an empty summary."}
    return {"status": "success", "summary": summary}


# ---------------------------------------------------------------------------
# Background diarisation jobs
#
# The client uploads every audio chunk once and may then close entirely. The
# work runs here and the result is written to Cosmos, so it is still waiting
# when the user comes back.
#
# The worker is a plain daemon thread inside this web process rather than a
# separate service, for the reason the sibling project documents: Render has no
# free Background Worker tier, while Web Services do have one. RQ and Redis are
# not used, because this vault already has Cosmos and one queue of long jobs
# does not need a broker.
#
# Honest limit: audio is staged on the instance's local disk, which Render
# wipes when a free instance spins down. Durability therefore covers the job
# record and its result, not a job caught mid-flight -- those are failed
# explicitly on the next boot instead of hanging forever. Moving JOB_AUDIO_DIR
# to blob storage is what would close that gap.
# ---------------------------------------------------------------------------
JOB_AUDIO_DIR = os.path.join(tempfile.gettempdir(), "threadnotes-jobs")

# Cosmos rejects documents over 2 MB. A long diarised transcript carrying word
# timings can approach that, so the result is degraded rather than lost.
JOB_DOC_SOFT_LIMIT = 1_500_000

_jobs_cont = None


def get_jobs_container():
    """The jobs container, created on first use so no manual setup is needed."""
    global _jobs_cont
    if _jobs_cont is None:
        endpoint, key, database_name = cosmos_config()
        from azure.cosmos import PartitionKey

        client = CosmosClient(endpoint, key)
        database = client.get_database_client(database_name)
        _jobs_cont = database.create_container_if_not_exists(
            id=secret("COSMOS_JOBS_CONTAINER", "diarizeJobs"),
            partition_key=PartitionKey(path="/email"),
        )
    return _jobs_cont


def _job_public(doc: dict) -> dict:
    """The job as the client sees it. Segments ride along only once ready."""
    out = {
        "job_id": doc.get("id"),
        "status": doc.get("status"),
        "topic": doc.get("topic"),
        "meeting_id": doc.get("meeting_id"),
        "duration_sec": doc.get("duration_sec"),
        "created_at": doc.get("created_at"),
        "completed_at": doc.get("completed_at"),
        "error": doc.get("error"),
        "words_dropped": doc.get("words_dropped", False),
    }
    if doc.get("status") == "completed":
        out["segments"] = doc.get("segments") or []
    return out


def _job_save(doc: dict):
    try:
        get_jobs_container().upsert_item(doc)
    except Exception:
        traceback.print_exc()


def _job_audio_paths(job_id: str) -> List[str]:
    folder = os.path.join(JOB_AUDIO_DIR, job_id)
    if not os.path.isdir(folder):
        return []
    return [os.path.join(folder, n) for n in sorted(os.listdir(folder))]


def _job_cleanup(job_id: str):
    folder = os.path.join(JOB_AUDIO_DIR, job_id)
    try:
        if os.path.isdir(folder):
            for n in os.listdir(folder):
                try:
                    os.remove(os.path.join(folder, n))
                except OSError:
                    pass
            os.rmdir(folder)
    except OSError:
        pass


def _run_job(job_id: str, email: str, segment_seconds: float):
    """Diarise each staged chunk, offsetting it into whole-recording time."""
    try:
        doc = get_jobs_container().read_item(item=job_id, partition_key=email)
    except Exception:
        traceback.print_exc()
        return

    doc["status"] = "processing"
    doc["started_at"] = datetime.now(timezone.utc).isoformat()
    _job_save(doc)

    try:
        paths = _job_audio_paths(job_id)
        if not paths:
            raise RuntimeError("The uploaded audio is no longer on disk.")

        segments: List[dict] = []
        for i, path in enumerate(paths):
            with open(path, "rb") as fh:
                audio = fh.read()
            if not audio:
                continue
            offset = i * float(segment_seconds or 0)
            for seg in _run_diarization(
                audio, os.path.basename(path), doc.get("content_type") or "audio/ogg"
            ):
                seg = dict(seg)
                seg["start"] = round(float(seg.get("start", 0.0)) + offset, 3)
                seg["end"] = round(float(seg.get("end", 0.0)) + offset, 3)
                if isinstance(seg.get("words"), list):
                    seg["words"] = [
                        {
                            "word": w.get("word", ""),
                            "start": round(float(w.get("start", 0.0)) + offset, 3),
                            "end": round(float(w.get("end", 0.0)) + offset, 3),
                        }
                        for w in seg["words"]
                    ]
                segments.append(seg)

        doc["segments"] = segments
        doc["words_dropped"] = False
        # Shed word timings before the whole result becomes unsavable.
        if len(json.dumps(doc)) > JOB_DOC_SOFT_LIMIT:
            for seg in doc["segments"]:
                seg.pop("words", None)
            doc["words_dropped"] = True

        doc["status"] = "completed"
        doc["error"] = None
    except Exception as exc:
        traceback.print_exc()
        doc["status"] = "failed"
        doc["error"] = _friendly_diarize_error(exc)
        doc["segments"] = []
    finally:
        doc["completed_at"] = datetime.now(timezone.utc).isoformat()
        _job_save(doc)
        _job_cleanup(job_id)


def _fail_orphaned_jobs():
    """Jobs still marked running at boot lost their audio when we restarted.

    Without this they sit at "processing" forever, because the thread that
    owned them no longer exists.
    """
    try:
        cont = get_jobs_container()
        stale = list(
            cont.query_items(
                "SELECT * FROM c WHERE c.status = 'queued' OR c.status = 'processing'",
                enable_cross_partition_query=True,
            )
        )
    except Exception:
        return
    for doc in stale:
        doc["status"] = "failed"
        doc["error"] = (
            "The server restarted while this was processing. Please run it again."
        )
        doc["completed_at"] = datetime.now(timezone.utc).isoformat()
        _job_save(doc)
    if stale:
        print(f"[jobs] failed {len(stale)} job(s) orphaned by a restart")


@app.on_event("startup")
def _jobs_startup():
    try:
        os.makedirs(JOB_AUDIO_DIR, exist_ok=True)
    except OSError:
        pass
    _fail_orphaned_jobs()


@app.post("/jobs/diarize")
async def create_diarize_job(
    files: List[UploadFile] = File(...),
    duration_sec: float = Form(0.0),
    segment_seconds: float = Form(1400.0),
    topic_guess: str = Form("Background diarisation"),
    meeting_id: str = Form(""),
    user: dict = Depends(get_current_user),
):
    """Stage the audio, record the job, start work, and return immediately."""
    email = user.get("sub") or user.get("email") or ""
    if not email:
        raise HTTPException(status_code=401, detail="Could not identify the account.")
    if not files:
        raise HTTPException(status_code=400, detail="No audio was uploaded.")

    job_id = str(uuid.uuid4())
    folder = os.path.join(JOB_AUDIO_DIR, job_id)
    os.makedirs(folder, exist_ok=True)

    total = 0
    content_type = None
    for i, up in enumerate(files):
        data = await up.read()
        if not data:
            continue
        total += len(data)
        # Azure picks the decoder from the file extension and rejects unknown
        # ones outright ("Unsupported file format bin"), so the uploaded
        # extension has to survive staging. Zero-padded so listdir() sorts
        # back into recording order.
        ext = os.path.splitext(up.filename or "")[1].lower()
        if not ext or len(ext) > 6:
            ext = ".ogg"
        if content_type is None and up.content_type:
            content_type = up.content_type
        with open(os.path.join(folder, "%04d%s" % (i, ext)), "wb") as fh:
            fh.write(data)
    if total == 0:
        _job_cleanup(job_id)
        raise HTTPException(status_code=400, detail="The uploaded audio was empty.")

    doc = {
        "id": job_id,
        "email": email,
        "status": "queued",
        "topic": topic_guess or "Background diarisation",
        "meeting_id": meeting_id or "",
        "duration_sec": duration_sec or 0.0,
        "segment_seconds": segment_seconds or 0.0,
        "content_type": content_type or "audio/ogg",
        "created_at": datetime.now(timezone.utc).isoformat(),
        "started_at": None,
        "completed_at": None,
        "error": None,
        "segments": [],
        "acked": False,
    }
    get_jobs_container().create_item(doc)

    threading.Thread(
        target=_run_job,
        args=(job_id, email, segment_seconds or 0.0),
        daemon=True,
    ).start()

    return {"status": "success", "job_id": job_id, "job": _job_public(doc)}


@app.get("/jobs/diarize/pending")
def list_pending_diarize_jobs(user: dict = Depends(get_current_user)):
    """Every job this account has not acknowledged yet, oldest first."""
    email = user.get("sub") or user.get("email") or ""
    if not email:
        raise HTTPException(status_code=401, detail="Could not identify the account.")
    try:
        docs = list(
            get_jobs_container().query_items(
                "SELECT * FROM c WHERE c.email = @e AND c.acked = false "
                "ORDER BY c.created_at ASC",
                parameters=[{"name": "@e", "value": email}],
                enable_cross_partition_query=True,
            )
        )
    except Exception:
        traceback.print_exc()
        return {"status": "success", "jobs": []}
    return {"status": "success", "jobs": [_job_public(d) for d in docs]}


@app.post("/jobs/diarize/{job_id}/ack")
def ack_diarize_job(job_id: str, user: dict = Depends(get_current_user)):
    """Mark a finished job as consumed so it stops being handed out."""
    email = user.get("sub") or user.get("email") or ""
    try:
        doc = get_jobs_container().read_item(item=job_id, partition_key=email)
    except Exception:
        raise HTTPException(status_code=404, detail="That job does not exist.")
    doc["acked"] = True
    _job_save(doc)
    return {"status": "success"}


@app.get("/")
async def root():
    return {"status": "ok", "message": "ThreadNotes Cloud Vault is running."}


if __name__ == "__main__":
    import uvicorn

    uvicorn.run(app, host="0.0.0.0", port=int(os.getenv("PORT", "8000")), log_level="info")
